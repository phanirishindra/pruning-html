#!/usr/bin/env python3
"""
=============================================================================
  TPU CONFIG  -  Shared Configuration for TPU Notebook Cells
=============================================================================

  IMPORTANT: This pipeline does NOT use AirLLM.
  AirLLM is CUDA-only (GPU). TPU uses XLA, a completely different backend.

  Instead, this pipeline uses:
  - PyTorch/XLA for TPU device management
  - HuggingFace Transformers with native TPU support
  - Model sharding across TPU cores (8 cores on free tier)

  TPU Hardware (free tier):
  - Colab: TPU v2-8  ->  8 cores, 8 GB HBM each = 64 GB total
  - Kaggle: TPU v3-8 ->  8 cores, 16 GB HBM each = 128 GB total

  A 72B model in float16 needs ~144 GB. So:
  - Colab TPU v2: Use Qwen2.5-32B (fits in 64 GB) or 72B with int8
  - Kaggle TPU v3: Can fit Qwen2.5-72B in float16 across 8 cores

  Edit this cell FIRST before running anything else.
=============================================================================
"""

import os

# =============================================================================
#  USER SETTINGS
# =============================================================================

ROW_COUNT = 100  # <-- CHANGE THIS: number of rows to process

# Model selection for TPU
# Kaggle TPU v3 (128 GB): Can run 72B in float16
# Colab TPU v2 (64 GB):   Use 32B or smaller, or 72B with quantization
#
# Option 1: "Qwen/Qwen2.5-72B-Instruct"  - Best quality (Kaggle TPU only)
# Option 2: "Qwen/Qwen2.5-32B-Instruct"  - Works on both Colab & Kaggle TPU
# Option 3: "Qwen/Qwen2.5-7B-Instruct"   - Fast, fits anywhere
MODEL_ID = "Qwen/Qwen2.5-14B-Instruct"  # <-- CHANGE THIS

# Precision: "float16", "bfloat16" (TPU-native), or "float32"
# bfloat16 is the TPU-native format and gives best performance
DTYPE = "bfloat16"  # <-- CHANGE THIS

# Token budget per row in final CSV
MAX_TOKENS_PER_ROW = 8000
MAX_NEW_TOKENS = 4096

# Generation parameters
TEMPERATURE = 0.5
TOP_P = 0.9

# =============================================================================
#  DATASET SETTINGS
# =============================================================================
SOURCE_DATASET = "williambrach/html-description-content"
TOKENIZER_ID = "Qwen/Qwen2.5-14B-Instruct"
HTML_BUDGET_RATIO = 0.40

# =============================================================================
#  PATHS
# =============================================================================
IS_COLAB = os.path.exists("/content") and not os.path.exists("/kaggle")
IS_KAGGLE = os.path.exists("/kaggle/working")

if IS_COLAB:
    WORK_DIR = "/content/cruzesolutions-project"
    CACHE_DIR = "/content/model_cache"
elif IS_KAGGLE:
    WORK_DIR = "/kaggle/working/cruzesolutions-project"
    CACHE_DIR = "/kaggle/temp/model_cache"
else:
    WORK_DIR = "."
    CACHE_DIR = "./model_cache"

REPO_URL = "https://gitlab.com/cruzesolutions-group/cruzesolutions-project.git"

_OUTPUT_FILE_1 = "newdataset-1-tpu.csv"
_OUTPUT_FILE_2 = "newdataset-2-tpu.csv"
_CHECKPOINT_FILE = ".tpu_checkpoint.json"
_TIMING_REPORT_FILE = "timing_report_tpu.json"

OUTPUT_FILE_1 = os.path.join(WORK_DIR, _OUTPUT_FILE_1)
OUTPUT_FILE_2 = os.path.join(WORK_DIR, _OUTPUT_FILE_2)
CHECKPOINT_FILE = os.path.join(WORK_DIR, _CHECKPOINT_FILE)
TIMING_REPORT_FILE = os.path.join(WORK_DIR, _TIMING_REPORT_FILE)

# =============================================================================
#  SYSTEM PROMPT  (identical to GPU version)
# =============================================================================
SYSTEM_PROMPT = """CRITICAL DIRECTIVES:
- Do NOT output any conversational text or greetings.
- VERBATIM TRANSLATION: You must not summarize, paraphrase, hallucinate or omit a single word from the user's HTML.
- Format your output EXACTLY with the dividers shown below.

For every raw HTML chunk the user provides, execute these 3 Tasks:

TASK 1: THE CLEANER (HTML -> Markdown)
Translate the HTML into strict Markdown. Preserve all |---| tables, code blocks, hyperlinks and links. Do NOT summarize.

TASK 2: THE INDEXER (Markdown -> Signpost)
Read the Markdown you just created. Write a Dense Signpost for it.
Format exactly: [Core Theme] + [Key Entities] + [Questions Answered] (Max 70 words).

TASK 3: THE ROUTER (Query Deconstruction)
Create EXACTLY THREE synthetic examples of a user asking a highly scrambled, slang-filled, multi-part query that matches the chunk you just processed.
For EACH of the three examples, you must output a separate USER_QUERY and ASSISTANT block.
The Assistant output must start with a <think> tag explaining the slang-to-entity translation, followed by a JSON array ["chunk_xyz"].

OUTPUT FORMAT:
===TASK 1===
<PERFECT MARKDOWN HERE>
===TASK 2===
[Theme] + [Entities] + [Answers]
===TASK 3===
USER_QUERY: <First Scrambled Slang Query>
ASSISTANT:
<think>...</think>
["chunk_xyz"]

USER_QUERY: <Second Scrambled Slang Query>
ASSISTANT:
<think>...</think>
["chunk_xyz"]

USER_QUERY: <Third Scrambled Slang Query>
ASSISTANT:
<think>...</think>
["chunk_xyz"]"""

# =============================================================================
print("\n" + "=" * 60)
print("  TPU NOTEBOOK CONFIG LOADED")
print("=" * 60)
print(f"  Environment:    {'Colab' if IS_COLAB else 'Kaggle' if IS_KAGGLE else 'Local'}")
print(f"  Model:          {MODEL_ID}")
print(f"  Dtype:          {DTYPE} (TPU-native: bfloat16)")
print(f"  Rows:           {ROW_COUNT}")
print(f"  Max tokens/row: {MAX_TOKENS_PER_ROW}")
print(f"  Backend:        PyTorch/XLA (NOT AirLLM)")
print(f"  Work dir:       {WORK_DIR}")
print(f"  Cache dir:      {CACHE_DIR}")
print("=" * 60)
