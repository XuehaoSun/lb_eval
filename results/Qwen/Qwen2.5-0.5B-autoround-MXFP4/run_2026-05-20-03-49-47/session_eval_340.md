# Session: autoeval_eval_340

- **Session ID:** `autoeval_eval_340`
- **Timestamp:** 2026-05-20 03:27:33 UTC
- **Working Dir:** `/root/.openclaw/workspace`

## Step 2: Evaluation

### [2026-05-20 03:27:33 UTC] USER

You are an expert in evaluating quantized LLM models.
You MUST follow the skill instructions in: /root/.openclaw/workspace/skills/auto_eval/SKILL.md

Quantized model path: /root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4
Runtime artifact directory: /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4
Raw lm_eval output directory: /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/lm_eval_results
Evaluation script path: /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/evaluate.sh
Evaluation execution log path: /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/logs/eval_exec.log
Evaluation tasks: piqa,mmlu,hellaswag
Batch size: 8
Num gpus: 1

The quantized model was produced by auto_quant with scheme=MXFP4, export_format=auto_round.
A venv may already exist at /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv (created by auto_quant with --system-site-packages).

CRITICAL ENVIRONMENT NOTE:
- System Python has torch+cuda pre-installed. When creating venvs, ALWAYS use:
    python3 -m venv --system-site-packages <path>
  This ensures the venv inherits torch+cuda. Do NOT pip install torch inside the venv.
- If /root/.venv exists, reuse /root/.venv before creating a new venv.
- If a venv already exists at /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv, reuse it - just install lm_eval and vllm into it.
- Use uv pip for dependency installation. Prefer:
    uv pip install --python <venv>/bin/python <packages>
- Do NOT reinstall torch or flash_attn if they already import successfully from the reused environment. Only install them when missing or incompatible.
- Write evaluation outputs, logs, prompts, copied request/session files, and other runtime artifacts to: /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4
- Before starting evaluation, you MUST first generate the evaluation script file:
    /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/evaluate.sh
- The file name must be exactly: evaluate.sh
- The script must be a standalone shell program runnable with:
    bash /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/evaluate.sh
- The generated evaluate.sh must focus on Stage A raw lm_eval execution only.
- Do NOT put venv creation, pip/uv installation, package bootstrap, JSON parsing, accuracy.json writing, or destructive cleanup/recreation into evaluate.sh.
- In this same OpenClaw task, prepare or reuse the evaluation environment separately before executing evaluate.sh.
- Prefer direct lm_eval CLI commands and standard shell environment variables over ad-hoc Python wrappers.
- In this same OpenClaw task, first write evaluate.sh, then execute that generated script yourself.
- When you execute evaluate.sh or a direct lm_eval command, you MUST stream stdout/stderr into this log file while still printing output:
    bash /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/evaluate.sh 2>&1 | tee /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/logs/eval_exec.log
- /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/accuracy.json is a final summary artifact, not a progress marker.
- After Stage A raw lm_eval completes, parse the latest raw results and write /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/accuracy.json in a separate finalize step outside evaluate.sh.
- Do NOT write a success /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/accuracy.json until Stage A raw lm_eval output and Stage B parsing have both completed successfully.
- Write /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/accuracy.json atomically via a temporary file and rename/move it into place only at finalize time.
- If evaluation fails, still write a minimal failed /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/accuracy.json before exiting non-zero, also atomically.
- The overall evaluation workflow MUST still behave as two idempotent stages:
    Stage A: run lm_eval and persist raw results under /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/lm_eval_results
    Stage B: parse the latest raw results into /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/accuracy.json
- Stage A and Stage B MUST be independently rerunnable.
- If /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/lm_eval_results already contains a valid raw results file matching , do NOT rerun Stage A; only rerun Stage B parsing.
- If Stage B parsing fails after Stage A already succeeded, exit non-zero but preserve the raw lm_eval outputs, logs, and venv so the next retry only reruns parsing.
- Do NOT delete or recreate /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/lm_eval_results when raw results already exist.
- Parsing logic should read the latest results file under /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/lm_eval_results/**/results_*.json rather than assuming lm_eval must be rerun.
- Do NOT leave the final artifact named eval.sh, eval_script.sh, or evaluate_script.sh.
- When the generated script invokes lm_eval, it MUST pass:
    --output_path /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/lm_eval_results
  and MUST set max_gen_toks=2048. The placement depends on the backend:
    - For HF backend (--model hf):   --gen_kwargs max_gen_toks=2048
    - For vLLM backend (--model vllm): append max_gen_toks=2048 inside --model_args
- Do NOT omit --output_path. Keep the raw lm_eval output files under that exact directory for later upload.
- Do NOT omit max_gen_toks=2048 regardless of backend.

IMPORTANT - In this same OpenClaw task, after separate raw-eval and finalize steps, you MUST produce:

/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/accuracy.json - evaluation results:
{
  "model_id": "Qwen/Qwen2.5-0.5B",
  "model_path": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
  "scheme": "MXFP4",
  "device": "cuda:0",
  "num_gpus": "1",
  "tasks": {
    "<task_name>": {
      "accuracy": <float>,
      "accuracy_stderr": <float or null>
    }
  },
  "status": "success" or "failed",
  "duration_seconds": <float>,
  "eval_framework": "lm_eval+vllm" or "lm_eval+hf" or "manual",
  "errors": [<list of error strings if any>]
}

/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/lm_eval_results/ - raw lm_eval output directory created by:
    lm_eval ... --output_path /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/lm_eval_results

The accuracy values MUST be real numbers from actual evaluation runs.
Write as valid JSON. If evaluation fails, the script may invoke python only for JSON post-processing, but it must still write accuracy.json with status=failed before exiting non-zero.

### [2026-05-20 03:27:37 UTC] ASSISTANT

**Thinking**

Let me start by reading the skill file to understand the evaluation process, then check what exists in the target directories.

**Tool call:** `read`

```json
{
  "file_path": "/root/.openclaw/workspace/skills/auto_eval/SKILL.md"
}
```

### [2026-05-20 03:27:37 UTC] TOOL RESULT
**Tool:** `read`

---
name: auto_eval
description: Automatically evaluate quantized LLM models using HuggingFace (HF) inference backend and lm-evaluation-harness. Supports CUDA device with multi-GPU tensor parallelism. Detects Auto-Round quantization format and configures appropriate settings.
metadata:
  openclaw:
    emoji: "📊"
    homepage: https://github.com/EleutherAI/lm-evaluation-harness
    skillKey: auto-eval
    requires:
      bins: ["lm_eval"]
      env: ["torch", "transformers"]
      config: []
---

# Auto-Eval Skill

Use this skill when users want to evaluate quantized LLM models (especially Auto-Round quantized models) using HuggingFace backend and lm-evaluation-harness on CUDA GPUs.

## Overview

This skill provides a complete workflow for:
- **Detecting quantization format** from model metadata
- **Configuring HF backend** for CUDA with multi-GPU support
- **Running lm-eval** benchmarks (e.g., piqa, hellaswag, mmlu)
- **Handling OOM errors** with multi-GPU suggestions

**Supported tasks**: piqa, hellaswag, mmlu, arc, gsm8k, and many more via lm-eval

---

## Input Parameters

| Parameter | Description | Required | Default |
|-----------|-------------|----------|---------|
| `model_path` | Path to quantized model (local or HF) | Yes | - |
| `task` | Evaluation task (e.g., piqa, mmlu) | Yes | - |
| `output_path` | Directory for results | No | `./lm_eval_results` |
| `batch_size` | Batch size for evaluation | No | `1` |
| `num_gpus` | Number of GPUs to use for inference | No | `1` |
| `max_model_len` | Max sequence length | No | `8192` |
| `trust_remote_code` | Allow custom model code | No | `True` |
| `max_gen_toks` | Max tokens to generate (via `--gen_kwargs`) | No | `2048` |

## Environment / Dependency Rules (CRITICAL)

Prefer reusing an existing system venv before creating a new one:

```bash
if [ -x /root/.venv/bin/python ]; then
  VENV_PY=/root/.venv/bin/python
else
  python3 -m venv --system-site-packages {output_path}/venv
  VENV_PY={output_path}/venv/bin/python
fi
```

Rules:

1. Use `uv pip`, not plain `pip install`, for dependency installation
2. If `torch` already imports from the reused environment, keep it
3. If `flash_attn` already imports from the reused environment, keep it
4. Only reinstall `torch` / `flash_attn` when they are missing or clearly incompatible

## lm-eval Output Artifact Rule (CRITICAL)

Always run `lm_eval` with an explicit output directory and keep the generated files:

```bash
--output_path {output_path}
--gen_kwargs max_gen_toks=2048
```

Rules:

1. Do **not** omit `--output_path`
2. Do **not** omit `--gen_kwargs max_gen_toks=2048` — this is required for all evaluation runs
3. If the caller provides a concrete runtime path, use it exactly
4. Prefer the `lm_eval` CLI over ad-hoc wrappers so raw result artifacts are persisted automatically

---

## Step 1: Analyze Model and Detect Quantization Format

### Check quantization_config.json

```bash
# For Auto-Round quantized models
cat {model_path}/quantization_config.json
```

**Common quantization formats and HF support:**

| Format | packing_format | HF Support | Device |
|--------|---------------|-------------|--------|
| auto_gptq | `auto_gptq` | ✓ | CUDA |
| auto_awq | `auto_awq` | ✓ | CUDA |
| auto_round | `auto_round:auto_gptq` | ✓ | CUDA |
| llm_compressor | `auto_round:llm_compressor` | ✓ | CUDA |
| GGUF | `gguf` | ✓ (llama.cpp) | CPU |

### Example quantization_config.json for different formats:

**Auto-Round format:**
```json
{
  "bits": 4,
  "group_size": 128,
  "sym": true,
  "quant_method": "auto-round",
  "packing_format": "auto_round:auto_gptq"
}
```

**LLM-Compressor (MXFP4) format:**
```json
{
  "quant_method": "compressed-tensors",
  "format": "float-quantized",
  "config_groups": {...},
  "provider": "auto-round"
}
```

---

## Step 2: Configure HF Model Args

Based on quantization format and GPU count, configure appropriate HF arguments:

### For Single GPU (num_gpus=1)

**Recommended settings:**
```bash
--model_args pretrained=./quantized_model,\
dtype=bfloat16,\
device_map=auto,\
trust_remote_code=True
```

### For Multi-GPU (num_gpus > 1)

**Recommended settings using device_map + parallelized:**
```bash
--model_args pretrained=./quantized_model,\
dtype=bfloat16,\
device_map=auto,\
parallelize=True,\
trust_remote_code=True
```

**Alternative: tensor_parallel via model_args (for vLLM backend):**
```bash
--model_args pretrained=./quantized_model,\
dtype=bfloat16,\
tensor_parallel_size=$NUM_GPUS,\
trust_remote_code=True
```

### Key Parameters Explained

| Parameter | Description | Recommended |
|-----------|-------------|-------------|
| `dtype` | Data type | `bfloat16` for CUDA |
| `device_map` | Device placement | `auto` for automatic |
| `parallelize` | Multi-GPU parallelization | `True` when num_gpus > 1 |
| `trust_remote_code` | Allow custom model code | `True` |
| `max_model_len` | Max sequence length | 8192 (adjust based on VRAM) |

### Format-Specific Model Args

**For auto_gptq format:**
```bash
--model_args pretrained=./quantized_model,dtype=bfloat16,device_map=auto,trust_remote_code=True
```

**For auto_round format:**
```bash
--model_args pretrained=./quantized_model,dtype=bfloat16,device_map=auto,trust_remote_code=True
```

**For llm_compressor (MXFP4/NVFP4) format:**
```bash
--model_args pretrained=./quantized_model,dtype=bfloat16,device_map=auto,trust_remote_code=True
```

---

## Step 3: Run lm-eval

### Basic Command (Single GPU)

```bash
lm_eval \
    --model hf \
    --model_args pretrained=./quantized_model,dtype=bfloat16,device_map=auto,trust_remote_code=True \
    --tasks piqa \
    --batch_size 1 \
    --output_path lm_eval_results \
    --gen_kwargs max_gen_toks=2048 \
    --device cuda
```

### Multi-GPU Command (User specifies GPU count)

```bash
# Example: use 2 GPUs (CUDA_VISIBLE_DEVICES=0,1)
export CUDA_VISIBLE_DEVICES=0,1
export NUM_GPUS=2

lm_eval \
    --model hf \
    --model_args pretrained=./quantized_model,dtype=bfloat16,device_map=auto,parallelize=True,trust_remote_code=True \
    --tasks piqa \
    --batch_size 1 \
    --output_path lm_eval_results \
    --gen_kwargs max_gen_toks=2048 \
    --device cuda
```

### Running Multiple Tasks

```bash
# Multiple tasks
lm_eval \
    --model hf \
    --model_args pretrained=./quantized_model,dtype=bfloat16,device_map=auto,trust_remote_code=True \
    --tasks piqa,hellaswag,mmlu \
    --batch_size 1 \
    --output_path lm_eval_results \
    --gen_kwargs max_gen_toks=2048 \
    --device cuda

# Task group
lm_eval \
    --model hf \
    --model_args pretrained=./quantized_model,dtype=bfloat16,device_map=auto,trust_remote_code=True \
    --tasks arc_easy,arc_challenge,piqa,hellaswag \
    --batch_size 1 \
    --output_path lm_eval_results \
    --gen_kwargs max_gen_toks=2048 \
    --device cuda
```

### Using lm_eval Python API

```python
import lm_eval

results = lm_eval.simple_evaluate(
    model="hf",
    model_args="pretrained=./quantized_model,dtype=bfloat16,device_map=auto,trust_remote_code=True",
    tasks="piqa",
    batch_size="auto",
    device="cuda",
    gen_kwargs={"max_gen_toks": 2048}
)
print(results["versions"])
```

---

## Step 4: Common Tasks

| Task | Description | Fewshot |
|------|-------------|---------|
| piqa | Physical interaction QA | 0 |
| hellaswag | commonsense inference | 10 |
| mmlu | multitask language understanding | 5 |
| arc | abstract reasoning | 0 |
| gsm8k | grade school math | 3 |
| winogrande | Winograd schema | 0 |
| boolq | boolean questions | 0 |
| cb | commitment bank | 0 |
| copa | causal reasoning | 0 |

### List Available Tasks

```bash
lm_eval ls tasks
```

---

## Step 5: Troubleshooting

### Common Errors and Solutions

#### 1. HF Backend Not Found

**Error:**
```
ValueError: Unknown model: hf
```

**Solution:**
```bash
# Install lm-eval with HF support
$VENV_PY -m pip install -U uv
uv pip install --python "$VENV_PY" lm-eval[torch]

# Or ensure transformers is importable
"$VENV_PY" -c "import transformers; print(transformers.__version__)"
```

#### 2. CUDA Device Not Available

**Error:**
```
RuntimeError: CUDA not available
```

**Solution:**
```bash
# Check CUDA availability
python -c "import torch; print('CUDA:', torch.cuda.is_available()); print('Devices:', torch.cuda.device_count())"

# Verify GPU visibility
nvidia-smi
```

#### 3. OOM on CUDA

**Error:**
```
RuntimeError: CUDA out of memory
```

**Solutions (in order of preference):**

1. **Use multi-GPU (RECOMMENDED):**
   ```bash
   # Set CUDA_VISIBLE_DEVICES to use multiple GPUs
   export CUDA_VISIBLE_DEVICES=0,1
   export NUM_GPUS=2
   
   # Use parallelize=True in model_args
   --model_args ...parallelize=True
   ```

2. **Reduce max_model_len:**
   ```bash
   --model_args ...max_model_len=2048
   ```

3. **Reduce batch_size:**
   ```bash
   --batch_size 1
   ```

4. **Reduce gpu_memory_utilization (if using device_map):**
   ```bash
   --model_args ...offload_folder="./offload"
   ```

#### 4. Quantization Format Not Supported

**Error:**
```
RuntimeError: Unsupported quantization format
```

**Solution:**
```python
# Check quantization_config.json format
# For unsupported formats, try with trust_remote_code=True
--model_args ...trust_remote_code=True
```

#### 5. Import Error: transformers module

**Error:**
```
ModuleNotFoundError: No module named 'transformers'
```

**Solution:**
```bash
# Install transformers
uv pip install --python "$VENV_PY" transformers

# Install with accelerator for better GPU support
uv pip install --python "$VENV_PY" transformers accelerate
```

#### 6. Multi-GPU Parallelization Error

**Error:**
```
RuntimeError: parallelize=True requires multiple GPUs
```

**Solution:**
```bash
# Make sure CUDA_VISIBLE_DEVICES has multiple GPUs
export CUDA_VISIBLE_DEVICES=0,1,2,3
export NUM_GPUS=4

# Verify GPU count
python -c "import torch; print(torch.cuda.device_count())"
```

---

## Step 6: Evaluation Script Template

### Complete Evaluation Script

```python
#!/usr/bin/env python3
"""
Auto-Eval Script for Quantized Models (CUDA + HF Backend)
"""

import argparse
import json
import os
from pathlib import Path


def detect_quantization_format(model_path: str) -> dict:
    """Detect quantization format from model metadata."""
    quant_config_path = Path(model_path) / "quantization_config.json"
    
    if not quant_config_path.exists():
        return {"format": "bf16", "method": "none"}
    
    with open(quant_config_path) as f:
        config = json.load(f)
    
    # Detect format
    quant_method = config.get("quant_method", "")
    packing_format = config.get("packing_format", "")
    
    if "auto-round" in quant_method:
        if "llm_compressor" in packing_format:
            return {"format": "llm_compressor", "method": "auto-round"}
        return {"format": "auto_round", "method": "auto-round"}
    elif "auto-gptq" in quant_method:
        return {"format": "auto_gptq", "method": "gptq"}
    elif "auto-awq" in quant_method:
        return {"format": "auto_awq", "method": "awq"}
    elif "compressed-tensors" in quant_method:
        return {"format": "compressed_tensors", "method": "auto-round"}
    
    return {"format": "unknown", "method": quant_method}


def build_hf_args(model_path: str, num_gpus: int = 1, **kwargs) -> str:
    """Build HF model arguments string."""
    
    # Base args
    args = [
        f"pretrained={model_path}",
        "dtype=bfloat16",
        "trust_remote_code=True",
    ]
    
    # Multi-GPU settings
    if num_gpus > 1:
        args.append("device_map=auto")
        args.append("parallelize=True")
    else:
        args.append("device_map=auto")
    
    # Add user overrides
    max_model_len = kwargs.get("max_model_len", 8192)
    
    return ",".join(args)


def run_evaluation(
    model_path: str,
    tasks: str,
    output_path: str = "./lm_eval_results",
    batch_size: int = 1,
    num_gpus: int = 1,
    **kwargs
):
    """Run lm-eval evaluation using HF backend."""
    import lm_eval
    
    # Detect format
    quant_info = detect_quantization_format(model_path)
    print(f"Detected quantization: {quant_info}")
    print(f"Using {num_gpus} GPU(s)")
    
    # Build model args
    model_args = build_hf_args(model_path, num_gpus, **kwargs)
    print(f"Model args: {model_args}")
    
    # Run evaluation
    results = lm_eval.simple_evaluate(
        model="hf",
        model_args=model_args,
        tasks=tasks,
        batch_size=str(batch_size),
        device="cuda",
        output_path=output_path,
        gen_kwargs={"max_gen_toks": 2048}
    )
    
    # Print results
    print("\n=== Evaluation Results ===")
    for task, metrics in results["results"].items():
        print(f"\n{task}:")
        for metric, value in metrics.items():
            if isinstance(value, (int, float)):
                print(f"  {metric}: {value:.4f}")
    
    # Save results
    os.makedirs(output_path, exist_ok=True)
    result_file = os.path.join(output_path, "results.json")
    with open(result_file, "w") as f:
        json.dump(results, f, indent=2)
    print(f"\nResults saved to: {result_file}")
    
    return results


if __name__ == "__main__":
    parser = argparse.ArgumentParser(description="Auto-Eval for Quantized Models (CUDA+HF)")
    parser.add_argument("--model", required=True, help="Path to model")
    parser.add_argument("--tasks", required=True, help="Comma-separated tasks")
    parser.add_argument("--output", default="./lm_eval_results", help="Output dir")
    parser.add_argument("--batch_size", type=int, default=1)
    parser.add_argument("--num_gpus", type=int, default=1, help="Number of GPUs to use")
    parser.add_argument("--max_model_len", type=int, default=8192)
    
    args = parser.parse_args()
    
    run_evaluation(
        model_path=args.model,
        tasks=args.tasks,
        output_path=args.output,
        batch_size=args.batch_size,
        num_gpus=args.num_gpus,
        max_model_len=args.max_model_len
    )
```

### Usage Example

```bash
# Single GPU evaluation
python eval_script.py \
    --model /path/to/quantized \
    --tasks piqa,hellaswag \
    --output ./results \
    --batch_size 1 \
    --num_gpus 1

# Multi-GPU evaluation (2 GPUs)
export CUDA_VISIBLE_DEVICES=0,1
python eval_script.py \
    --model /path/to/quantized \
    --tasks piqa,hellaswag \
    --output ./results \
    --batch_size 1 \
    --num_gpus 2
```

---

## Step 7: Environment Setup

### Install Dependencies

```bash
# Reuse the system venv if present; otherwise create a local one
if [ -x /root/.venv/bin/python ]; then
  VENV_PY=/root/.venv/bin/python
else
  python3 -m venv --system-site-packages {output_path}/venv
  VENV_PY={output_path}/venv/bin/python
fi

# Bootstrap uv
$VENV_PY -m pip install -U uv

# Keep inherited CUDA packages when they already work
"$VENV_PY" -c "import torch; print('CUDA:', torch.cuda.is_available(), 'Devices:', torch.cuda.device_count())"
"$VENV_PY" -c "import flash_attn; print('flash_attn ok')" || true

# Install transformers and accelerate
uv pip install --python "$VENV_PY" transformers accelerate

# Install lm-eval with torch
uv pip install --python "$VENV_PY" lm-eval[torch]

# Only if torch is missing or incompatible, install a matching CUDA wheel
# uv pip install --python "$VENV_PY" --index-url https://download.pytorch.org/whl/cu124 torch

# Only if flash_attn is required and missing
# uv pip install --python "$VENV_PY" flash-attn --no-build-isolation

# Verify installations
"$VENV_PY" -c "import torch; print('CUDA:', torch.cuda.is_available(), 'Devices:', torch.cuda.device_count())"
"$VENV_PY" -c "import transformers; print('Transformers:', transformers.__version__)"
"$VENV_PY" -c "import lm_eval; print('lm-eval:', lm_eval.__version__)"
```

---

## Step 8: Quick Reference

### Complete Example for Auto-Round W4A16 Model (Single GPU)

```bash
# Model path
MODEL_PATH="/path/to/quantized"

# Run piqa evaluation
lm_eval \
    --model hf \
    --model_args "pretrained=$MODEL_PATH,dtype=bfloat16,device_map=auto,trust_remote_code=True" \
    --tasks piqa \
    --batch_size 1 \
    --output_path ./lm_eval_results \
    --gen_kwargs max_gen_toks=2048 \
    --device cuda
```

### Complete Example for Auto-Round W4A16 Model (Multi-GPU)

```bash
# Model path
MODEL_PATH="/path/to/quantized"

# Use 2 GPUs
export CUDA_VISIBLE_DEVICES=0,1
export NUM_GPUS=2

# Run piqa evaluation with multi-GPU
lm_eval \
    --model hf \
    --model_args "pretrained=$MODEL_PATH,dtype=bfloat16,device_map=auto,parallelize=True,trust_remote_code=True" \
    --tasks piqa \
    --batch_size 1 \
    --output_path ./lm_eval_results \
    --gen_kwargs max_gen_toks=2048 \
    --device cuda
```

### Run Multiple Benchmarks

```bash
lm_eval \
    --model hf \
    --model_args "pretrained=$MODEL_PATH,dtype=bfloat16,device_map=auto,trust_remote_code=True" \
    --tasks piqa,hellaswag,mmlu,arc_easy \
    --batch_size 1 \
    --output_path ./results \
    --gen_kwargs max_gen_toks=2048 \
    --device cuda
```

### Using Python API

```python
import lm_eval

results = lm_eval.simple_evaluate(
    model="hf",
    model_args="pretrained=/path/to/quantized,dtype=bfloat16,device_map=auto,trust_remote_code=True",
    tasks="piqa",
    batch_size="auto",
    device="cuda",
    gen_kwargs={"max_gen_toks": 2048}
)
print(results["results"]["piqa"])
```

---

## OOM Resolution Guide

When encountering CUDA out of memory errors, follow this decision tree:

1. **First try: Multi-GPU** (Most effective)
   ```bash
   export CUDA_VISIBLE_DEVICES=0,1  # 2 GPUs
   --model_args ...parallelize=True
   ```

2. **Second try: Reduce max_model_len**
   ```bash
   --model_args ...max_model_len=2048
   ```

3. **Third try: Reduce batch_size**
   ```bash
   --batch_size 1
   ```

4. **Fourth try: Enable CPU offload**
   ```bash
   --model_args ...offload_folder="./offload"
   ```

---

## Notes

- **Multi-GPU requires `parallelize=True`** - Enables model parallelism across GPUs
- **Batch size** - Use `1` or `auto` for quantized models to avoid OOM
- **Quantization formats** - Auto-Round exports to `auto_round` format with `packing_format` metadata
- **device_map=auto** - Automatically places layers on available GPUs
- **trust_remote_code=True** - Required for custom model architectures


### [2026-05-20 03:27:43 UTC] ASSISTANT

**Thinking**

Let me now check the existing directories and files to understand the current state.

**Tool call:** `exec`

```json
{
  "command": "ls -la /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/ 2>/dev/null || echo \"Directory not found\"\nls -la /root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4/ 2>/dev/null | head -20"
}
```

### [2026-05-20 03:27:43 UTC] TOOL RESULT
**Tool:** `exec` | **Status:** `completed` | **Exit code:** `0`

total 108
drwxr-xr-x 5 root root   179 May 20 03:27 .
drwxr-xr-x 3 root root    45 May 20 03:21 ..
drwxr-xr-x 2 root root    10 May 20 03:23 ar_work_space
drwxr-xr-x 2 root root   118 May 20 03:27 logs
-rw-r--r-- 1 root root   823 May 20 03:25 quant_summary.json
-rw-r--r-- 1 root root  1404 May 20 03:23 quantize.py
-rw-r--r-- 1 root root  1073 May 20 03:21 request.json
-rw-r--r-- 1 root root 95937 May 20 03:27 session_quant_340.jsonl
drwxr-xr-x 6 root root   132 May 20 03:22 venv
total 462900
drwxr-xr-x 2 root root      4096 May 20 03:23 .
drwxr-xr-x 4 root root        61 May 20 03:22 ..
-rw-r--r-- 1 root root      2427 May 20 03:23 chat_template.jinja
-rw-r--r-- 1 root root      1673 May 20 03:23 config.json
-rw-r--r-- 1 root root       137 May 20 03:23 generation_config.json
-rw-r--r-- 1 root root 462560232 May 20 03:23 model.safetensors
-rw-r--r-- 1 root root       313 May 20 03:23 quantization_config.json
-rw-r--r-- 1 root root  11421892 May 20 03:23 tokenizer.json
-rw-r--r-- 1 root root       697 May 20 03:23 tokenizer_config.json

### [2026-05-20 03:27:48 UTC] ASSISTANT

**Thinking**

Let me check the quantization_config.json to understand the format, and also check if there's an existing venv or lm_eval_results.

**Tool call:** `read`

```json
{
  "file_path": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4/quantization_config.json"
}
```

**Tool call:** `exec`

```json
{
  "command": "ls -la /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/lm_eval_results/ 2>/dev/null || echo \"No lm_eval_results yet\"\nls -la /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/logs/ 2>/dev/null\nls -la /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/ 2>/dev/null | head -5"
}
```

### [2026-05-20 03:27:48 UTC] TOOL RESULT
**Tool:** `read`

{
  "bits": 4,
  "act_bits": 4,
  "data_type": "mx_fp",
  "act_data_type": "mx_fp",
  "group_size": 32,
  "act_group_size": 32,
  "sym": true,
  "act_sym": true,
  "act_dynamic": true,
  "iters": 0,
  "autoround_version": "0.12.3",
  "quant_method": "auto-round",
  "packing_format": "auto_round:llm_compressor"
}

### [2026-05-20 03:27:48 UTC] TOOL RESULT
**Tool:** `exec` | **Status:** `completed` | **Exit code:** `0`

No lm_eval_results yet
total 68
drwxr-xr-x 2 root root   118 May 20 03:27 .
drwxr-xr-x 5 root root   179 May 20 03:27 ..
-rw-r--r-- 1 root root 41646 May 20 03:27 auto.log
-rw-r--r-- 1 root root  6854 May 20 03:27 eval_script_prompt.txt
-rw-r--r-- 1 root root  6658 May 20 03:23 quant_exec.log
-rw-r--r-- 1 root root  4913 May 20 03:21 quant_prompt.txt
total 8
drwxr-xr-x 6 root root  132 May 20 03:22 .
drwxr-xr-x 5 root root  179 May 20 03:27 ..
-rw-rw-rw- 1 root root    0 May 20 03:22 .lock
drwxr-xr-x 2 root root 4096 May 20 03:22 bin

### [2026-05-20 03:27:53 UTC] ASSISTANT

**Thinking**

Good. The venv already exists. Let me check what's in the venv and if lm_eval is installed.

**Tool call:** `exec`

```json
{
  "command": "ls /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/bin/ | head -20\n/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/bin/python -c \"import torch; print('torch:', torch.__version__, 'CUDA:', torch.cuda.is_available())\" 2>&1\n/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/bin/python -c \"import transformers; print('transformers:', transformers.__version__)\" 2>&1\n/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/bin/python -c \"import lm_eval; print('lm_eval ok')\" 2>&1"
}
```

### [2026-05-20 03:27:56 UTC] TOOL RESULT
**Tool:** `exec` | **Status:** `completed` | **Exit code:** `1`

Activate.ps1
accelerate
accelerate-config
accelerate-estimate-memory
accelerate-launch
accelerate-merge-weights
activate
activate.csh
activate.fish
auto-round
auto-round-best
auto-round-eval
auto-round-fast
auto-round-lib-install
auto-round-light
auto-round-mllm
auto_round
auto_round_best
auto_round_eval
auto_round_fast
torch: 2.6.0+cu124 CUDA: True
transformers: 5.8.1
Traceback (most recent call last):
  File "<string>", line 1, in <module>
ModuleNotFoundError: No module named 'lm_eval'

(Command exited with code 1)

### [2026-05-20 03:28:00 UTC] ASSISTANT

**Thinking**

lm_eval is not installed yet. Let me install it. I also need to check if vllm is needed or if we can use HF backend. The task uses `--model hf` so I'll use HF backend. Let me install lm_eval.

**Tool call:** `exec`

```json
{
  "command": "cd /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4 && \\\n/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/bin/python -m pip install -U uv 2>&1 | tail -3"
}
```

### [2026-05-20 03:28:01 UTC] TOOL RESULT
**Tool:** `exec` | **Status:** `completed` | **Exit code:** `0`

[notice] A new release of pip is available: 25.0.1 -> 26.1.1
[notice] To update, run: python -m pip install --upgrade pip

### [2026-05-20 03:28:04 UTC] ASSISTANT

**Thinking**

Let me install lm_eval with HF/torch support.

**Tool call:** `exec`

```json
{
  "command": "uv pip install --python /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/bin/python \"lm-eval[torch]\" 2>&1 | tail -10"
}
```

### [2026-05-20 03:28:13 UTC] TOOL RESULT
**Tool:** `exec` | **Status:** `completed` | **Exit code:** `0`

+ scikit-learn==1.8.0
 + scipy==1.17.1
 + sqlitedict==2.1.0
 + tabledata==1.3.5
 + tabulate==0.10.0
 + tcolorpy==0.1.7
 + threadpoolctl==3.6.0
 + typepy==1.3.5
 + word2number==1.1
warning: The package `lm-eval==0.4.12` does not have an extra named `torch`

### [2026-05-20 03:28:19 UTC] ASSISTANT

**Thinking**

lm_eval is installed. Let me verify it works.

**Tool call:** `exec`

```json
{
  "command": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/bin/python -c \"import lm_eval; print('lm_eval:', lm_eval.__version__)\" 2>&1\nwhich lm_eval 2>&1 || echo \"lm_eval not in PATH\"\n/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/bin/lm_eval --version 2>&1 || echo \"No lm_eval binary\""
}
```

### [2026-05-20 03:28:20 UTC] TOOL RESULT
**Tool:** `exec` | **Status:** `completed` | **Exit code:** `0`

lm_eval: 0.4.12
lm_eval not in PATH
usage: lm-eval [-h] COMMAND ...
lm-eval: error: unrecognized arguments: --version
No lm_eval binary

### [2026-05-20 03:28:29 UTC] ASSISTANT

**Thinking**

lm_eval is available as a Python module. Let me now write the evaluate.sh script.

The model path is `/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4`.
Tasks: piqa, mmlu, hellaswag
Batch size: 8
Num GPUs: 1
Output path: `/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/lm_eval_results`
Max gen toks: 2048

The model uses MXFP4 quantization with auto_round:llm_compressor format.


I'll use the HF backend with bfloat16, setting device_map to auto and trust_remote_code to True. I can invoke lm_eval directly as a module from the venv rather than needing a separate binary.

Now let me write the evaluation script:


**Tool call:** `write`

```json
{
  "path": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/evaluate.sh",
  "content": "#!/bin/bash\nset -euo pipefail\n\nMODEL_PATH=\"/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4\"\nOUTPUT_PATH=\"/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/lm_eval_results\"\nVENV_PY=\"/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/bin/python\"\nTASKS=\"piqa,mmlu,hellaswag\"\nBATCH_SIZE=8\nDEVICE=\"cuda\"\n\n\"$VENV_PY\" -m lm_eval \\\n    --model hf \\\n    --model_args \"pretrained=$MODEL_PATH,dtype=bfloat16,device_map=auto,trust_remote_code=True\" \\\n    --tasks \"$TASKS\" \\\n    --batch_size \"$BATCH_SIZE\" \\\n    --output_path \"$OUTPUT_PATH\" \\\n    --gen_kwargs max_gen_toks=2048 \\\n    --device \"$DEVICE\"\n"
}
```

### [2026-05-20 03:28:29 UTC] TOOL RESULT
**Tool:** `write`

Successfully wrote 636 bytes to /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/evaluate.sh

### [2026-05-20 03:28:33 UTC] ASSISTANT

**Thinking**

Now let me run the evaluation script.

**Tool call:** `exec`

```json
{
  "command": "chmod +x /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/evaluate.sh\nmkdir -p /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/lm_eval_results\nmkdir -p /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/logs"
}
```

### [2026-05-20 03:28:33 UTC] TOOL RESULT
**Tool:** `exec` | **Status:** `completed` | **Exit code:** `0`

(no output)

### [2026-05-20 03:28:37 UTC] ASSISTANT

**Thinking**

Now let me execute the evaluate.sh script and stream output to the log file.

**Tool call:** `exec`

```json
{
  "command": "cd /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4 && \\\nbash /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/evaluate.sh 2>&1 | tee /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/logs/eval_exec.log",
  "timeout": 1800
}
```

### [2026-05-20 03:28:47 UTC] TOOL RESULT
**Tool:** `exec` | **Status:** `running`

Command still running (session briny-otter, pid 1516). Use process (list/poll/log/write/kill/clear/remove) for follow-up.

### [2026-05-20 03:28:50 UTC] ASSISTANT

**Thinking**

The evaluation is running. Let me check on it.

**Tool call:** `process`

```json
{
  "action": "poll",
  "sessionId": "briny-otter",
  "timeout": 300000
}
```

### [2026-05-20 03:30:50 UTC] TOOL RESULT
**Tool:** `process` | **Status:** `running`

: 100%|██████████| 238/238 [00:00<00:00, 103799.97 examples/s]

Generating validation split:   0%|          | 0/26 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 26/26 [00:00<00:00, 16369.24 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 3518.71 examples/s]

Generating test split:   0%|          | 0/545 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 545/545 [00:00<00:00, 122844.78 examples/s]

Generating validation split:   0%|          | 0/60 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 60/60 [00:00<00:00, 23340.59 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 3136.16 examples/s]

Generating test split:   0%|          | 0/131 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 131/131 [00:00<00:00, 39714.77 examples/s]

Generating validation split:   0%|          | 0/12 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 12/12 [00:00<00:00, 4879.93 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 2285.23 examples/s]

Generating test split:   0%|          | 0/612 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 612/612 [00:00<00:00, 78472.50 examples/s]

Generating validation split:   0%|          | 0/69 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 69/69 [00:00<00:00, 12113.13 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 1781.78 examples/s]

Generating test split:   0%|          | 0/110 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 110/110 [00:00<00:00, 31685.56 examples/s]

Generating validation split:   0%|          | 0/12 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 12/12 [00:00<00:00, 5454.82 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 2567.84 examples/s]

Generating test split:   0%|          | 0/245 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 245/245 [00:00<00:00, 77147.48 examples/s]

Generating validation split:   0%|          | 0/27 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 27/27 [00:00<00:00, 19647.16 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 3440.21 examples/s]

Generating test split:   0%|          | 0/201 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 201/201 [00:00<00:00, 85329.46 examples/s]

Generating validation split:   0%|          | 0/22 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 22/22 [00:00<00:00, 16366.56 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 3867.86 examples/s]

Generating test split:   0%|          | 0/100 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 100/100 [00:00<00:00, 30675.81 examples/s]

Generating validation split:   0%|          | 0/11 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 11/11 [00:00<00:00, 5963.98 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 2953.74 examples/s]

Generating test split:   0%|          | 0/126 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 126/126 [00:00<00:00, 47173.28 examples/s]

Generating validation split:   0%|          | 0/14 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 14/14 [00:00<00:00, 9615.24 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 3797.81 examples/s]

Generating test split:   0%|          | 0/165 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 165/165 [00:00<00:00, 51214.40 examples/s]

Generating validation split:   0%|          | 0/18 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 18/18 [00:00<00:00, 8156.60 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 2205.67 examples/s]

Generating test split:   0%|          | 0/204 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 204/204 [00:00<00:00, 43872.12 examples/s]

Generating validation split:   0%|          | 0/22 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 22/22 [00:00<00:00, 8310.79 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 1626.08 examples/s]

Generating test split:   0%|          | 0/237 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 237/237 [00:00<00:00, 54195.29 examples/s]

Generating validation split:   0%|          | 0/26 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 26/26 [00:00<00:00, 10858.50 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 2483.31 examples/s]

Generating test split:   0%|          | 0/121 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 121/121 [00:00<00:00, 38579.31 examples/s]

Generating validation split:   0%|          | 0/13 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 13/13 [00:00<00:00, 6996.79 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 3413.89 examples/s]

Generating test split:   0%|          | 0/108 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 108/108 [00:00<00:00, 43656.98 examples/s]

Generating validation split:   0%|          | 0/11 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 11/11 [00:00<00:00, 7217.98 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 3320.91 examples/s]

Generating test split:   0%|          | 0/163 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 163/163 [00:00<00:00, 53684.46 examples/s]

Generating validation split:   0%|          | 0/18 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 18/18 [00:00<00:00, 10905.31 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 2874.39 examples/s]

Generating test split:   0%|          | 0/346 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 346/346 [00:00<00:00, 96826.07 examples/s]

Generating validation split:   0%|          | 0/38 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 38/38 [00:00<00:00, 16706.87 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 2656.64 examples/s]

Generating test split:   0%|          | 0/895 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 895/895 [00:00<00:00, 320025.75 examples/s]

Generating validation split:   0%|          | 0/100 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 100/100 [00:00<00:00, 63015.38 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 3470.96 examples/s]

Generating test split:   0%|          | 0/311 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 311/311 [00:00<00:00, 34993.79 examples/s]

Generating validation split:   0%|          | 0/34 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 34/34 [00:00<00:00, 7391.61 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 2128.44 examples/s]

Generating test split:   0%|          | 0/324 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 324/324 [00:00<00:00, 67482.10 examples/s]

Generating validation split:   0%|          | 0/35 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 35/35 [00:00<00:00, 11591.96 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 1384.81 examples/s]

Generating test split:   0%|          | 0/1534 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 1534/1534 [00:00<00:00, 151951.03 examples/s]

Generating validation split:   0%|          | 0/170 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 170/170 [00:00<00:00, 76984.63 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 3393.45 examples/s]

Generating test split:   0%|          | 0/171 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 171/171 [00:00<00:00, 60064.15 examples/s]

Generating validation split:   0%|          | 0/19 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 19/19 [00:00<00:00, 6266.55 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 2118.12 examples/s]

Generating train split:   0%|          | 0/39905 [00:00<?, ? examples/s]
Generating train split: 100%|██████████| 39905/39905 [00:00<00:00, 244248.11 examples/s]

Generating test split:   0%|          | 0/10003 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 10003/10003 [00:00<00:00, 240938.72 examples/s]

Generating validation split:   0%|          | 0/10042 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 10042/10042 [00:00<00:00, 234095.70 examples/s]

Map:   0%|          | 0/39905 [00:00<?, ? examples/s]
Map: 100%|██████████| 39905/39905 [00:03<00:00, 10771.98 examples/s]

Map:   0%|          | 0/10042 [00:00<?, ? examples/s]
Map: 100%|██████████| 10042/10042 [00:00<00:00, 14490.77 examples/s]
2026-05-20:03:29:44 INFO     [evaluator_utils:446] Selected tasks:
2026-05-20:03:29:44 INFO     [evaluator_utils:462] Group: mmlu
2026-05-20:03:29:44 INFO     [evaluator_utils:462]   Group: mmlu_stem
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_abstract_algebra (mmlu/default/mmlu_abstract_algebra.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_anatomy (mmlu/default/mmlu_anatomy.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_astronomy (mmlu/default/mmlu_astronomy.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_college_biology (mmlu/default/mmlu_college_biology.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_college_chemistry (mmlu/default/mmlu_college_chemistry.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_college_computer_science (mmlu/default/mmlu_college_computer_science.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_college_mathematics (mmlu/default/mmlu_college_mathematics.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_college_physics (mmlu/default/mmlu_college_physics.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_computer_security (mmlu/default/mmlu_computer_security.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_conceptual_physics (mmlu/default/mmlu_conceptual_physics.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_electrical_engineering (mmlu/default/mmlu_electrical_engineering.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_elementary_mathematics (mmlu/default/mmlu_elementary_mathematics.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_high_school_biology (mmlu/default/mmlu_high_school_biology.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_high_school_chemistry (mmlu/default/mmlu_high_school_chemistry.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_high_school_computer_science (mmlu/default/mmlu_high_school_computer_science.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_high_school_mathematics (mmlu/default/mmlu_high_school_mathematics.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_high_school_physics (mmlu/default/mmlu_high_school_physics.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_high_school_statistics (mmlu/default/mmlu_high_school_statistics.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_machine_learning (mmlu/default/mmlu_machine_learning.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:462]   Group: mmlu_other
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_business_ethics (mmlu/default/mmlu_business_ethics.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_clinical_knowledge (mmlu/default/mmlu_clinical_knowledge.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_college_medicine (mmlu/default/mmlu_college_medicine.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_global_facts (mmlu/default/mmlu_global_facts.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_human_aging (mmlu/default/mmlu_human_aging.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_management (mmlu/default/mmlu_management.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_marketing (mmlu/default/mmlu_marketing.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_medical_genetics (mmlu/default/mmlu_medical_genetics.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_miscellaneous (mmlu/default/mmlu_miscellaneous.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_nutrition (mmlu/default/mmlu_nutrition.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_professional_accounting (mmlu/default/mmlu_professional_accounting.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_professional_medicine (mmlu/default/mmlu_professional_medicine.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_virology (mmlu/default/mmlu_virology.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:462]   Group: mmlu_social_sciences
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_econometrics (mmlu/default/mmlu_econometrics.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_high_school_geography (mmlu/default/mmlu_high_school_geography.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_high_school_government_and_politics (mmlu/default/mmlu_high_school_government_and_politics.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_high_school_macroeconomics (mmlu/default/mmlu_high_school_macroeconomics.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_high_school_microeconomics (mmlu/default/mmlu_high_school_microeconomics.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_high_school_psychology (mmlu/default/mmlu_high_school_psychology.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_human_sexuality (mmlu/default/mmlu_human_sexuality.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_professional_psychology (mmlu/default/mmlu_professional_psychology.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_public_relations (mmlu/default/mmlu_public_relations.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_security_studies (mmlu/default/mmlu_security_studies.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_sociology (mmlu/default/mmlu_sociology.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_us_foreign_policy (mmlu/default/mmlu_us_foreign_policy.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:462]   Group: mmlu_humanities
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_formal_logic (mmlu/default/mmlu_formal_logic.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_high_school_european_history (mmlu/default/mmlu_high_school_european_history.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_high_school_us_history (mmlu/default/mmlu_high_school_us_history.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_high_school_world_history (mmlu/default/mmlu_high_school_world_history.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_international_law (mmlu/default/mmlu_international_law.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_jurisprudence (mmlu/default/mmlu_jurisprudence.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_logical_fallacies (mmlu/default/mmlu_logical_fallacies.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_moral_disputes (mmlu/default/mmlu_moral_disputes.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_moral_scenarios (mmlu/default/mmlu_moral_scenarios.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_philosophy (mmlu/default/mmlu_philosophy.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_prehistory (mmlu/default/mmlu_prehistory.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_professional_law (mmlu/default/mmlu_professional_law.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:470]     Task: mmlu_world_religions (mmlu/default/mmlu_world_religions.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:480] Task: hellaswag (hellaswag/hellaswag.yaml)
2026-05-20:03:29:44 INFO     [evaluator_utils:480] Task: piqa (piqa/piqa.yaml)
2026-05-20:03:29:44 INFO     [api.task:312] Building contexts for piqa on rank 0...

  0%|          | 0/1838 [00:00<?, ?it/s]
100%|██████████| 1838/1838 [00:01<00:00, 1164.35it/s]
2026-05-20:03:29:46 INFO     [api.task:312] Building contexts for mmlu_abstract_algebra on rank 0...

  0%|          | 0/100 [00:00<?, ?it/s]
100%|██████████| 100/100 [00:00<00:00, 1037.94it/s]
2026-05-20:03:29:46 INFO     [api.task:312] Building contexts for mmlu_anatomy on rank 0...

  0%|          | 0/135 [00:00<?, ?it/s]
100%|██████████| 135/135 [00:00<00:00, 1055.21it/s]
2026-05-20:03:29:46 INFO     [api.task:312] Building contexts for mmlu_astronomy on rank 0...

  0%|          | 0/152 [00:00<?, ?it/s]
100%|██████████| 152/152 [00:00<00:00, 930.22it/s]
2026-05-20:03:29:46 INFO     [api.task:312] Building contexts for mmlu_college_biology on rank 0...

  0%|          | 0/144 [00:00<?, ?it/s]
100%|██████████| 144/144 [00:00<00:00, 931.25it/s]
2026-05-20:03:29:46 INFO     [api.task:312] Building contexts for mmlu_college_chemistry on rank 0...

  0%|          | 0/100 [00:00<?, ?it/s]
100%|██████████| 100/100 [00:00<00:00, 1021.38it/s]
2026-05-20:03:29:46 INFO     [api.task:312] Building contexts for mmlu_college_computer_science on rank 0...

  0%|          | 0/100 [00:00<?, ?it/s]
100%|██████████| 100/100 [00:00<00:00, 1062.89it/s]
2026-05-20:03:29:46 INFO     [api.task:312] Building contexts for mmlu_college_mathematics on rank 0...

  0%|          | 0/100 [00:00<?, ?it/s]
100%|██████████| 100/100 [00:00<00:00, 1082.99it/s]
2026-05-20:03:29:47 INFO     [api.task:312] Building contexts for mmlu_college_physics on rank 0...

  0%|          | 0/102 [00:00<?, ?it/s]
100%|██████████| 102/102 [00:00<00:00, 1071.59it/s]
2026-05-20:03:29:47 INFO     [api.task:312] Building contexts for mmlu_computer_security on rank 0...

  0%|          | 0/100 [00:00<?, ?it/s]
100%|██████████| 100/100 [00:00<00:00, 1010.62it/s]
2026-05-20:03:29:47 INFO     [api.task:312] Building contexts for mmlu_conceptual_physics on rank 0...

  0%|          | 0/235 [00:00<?, ?it/s]
100%|██████████| 235/235 [00:00<00:00, 362.99it/s]
2026-05-20:03:29:47 INFO     [api.task:312] Building contexts for mmlu_electrical_engineering on rank 0...

  0%|          | 0/145 [00:00<?, ?it/s]
100%|██████████| 145/145 [00:00<00:00, 1038.45it/s]
2026-05-20:03:29:48 INFO     [api.task:312] Building contexts for mmlu_elementary_mathematics on rank 0...

  0%|          | 0/378 [00:00<?, ?it/s]
100%|██████████| 378/378 [00:00<00:00, 1021.72it/s]
2026-05-20:03:29:48 INFO     [api.task:312] Building contexts for mmlu_high_school_biology on rank 0...

  0%|          | 0/310 [00:00<?, ?it/s]
100%|██████████| 310/310 [00:00<00:00, 999.02it/s]
2026-05-20:03:29:48 INFO     [api.task:312] Building contexts for mmlu_high_school_chemistry on rank 0...

  0%|          | 0/203 [00:00<?, ?it/s]
100%|██████████| 203/203 [00:00<00:00, 1009.51it/s]
2026-05-20:03:29:48 INFO     [api.task:312] Building contexts for mmlu_high_school_computer_science on rank 0...

  0%|          | 0/100 [00:00<?, ?it/s]
100%|██████████| 100/100 [00:00<00:00, 1006.17it/s]
2026-05-20:03:29:49 INFO     [api.task:312] Building contexts for mmlu_high_school_mathematics on rank 0...

  0%|          | 0/270 [00:00<?, ?it/s]
100%|██████████| 270/270 [00:00<00:00, 1032.04it/s]
2026-05-20:03:29:49 INFO     [api.task:312] Building contexts for mmlu_high_school_physics on rank 0...

  0%|          | 0/151 [00:00<?, ?it/s]
100%|██████████| 151/151 [00:00<00:00, 1047.77it/s]
2026-05-20:03:29:49 INFO     [api.task:312] Building contexts for mmlu_high_school_statistics on rank 0...

  0%|          | 0/216 [00:00<?, ?it/s]
100%|██████████| 216/216 [00:00<00:00, 1018.97it/s]
2026-05-20:03:29:49 INFO     [api.task:312] Building contexts for mmlu_machine_learning on rank 0...

  0%|          | 0/112 [00:00<?, ?it/s]
100%|██████████| 112/112 [00:00<00:00, 1050.06it/s]
2026-05-20:03:29:49 INFO     [api.task:312] Building contexts for mmlu_business_ethics on rank 0...

  0%|          | 0/100 [00:00<?, ?it/s]
100%|██████████| 100/100 [00:00<00:00, 1023.38it/s]
2026-05-20:03:29:49 INFO     [api.task:312] Building contexts for mmlu_clinical_knowledge on rank 0...

  0%|          | 0/265 [00:00<?, ?it/s]
100%|██████████| 265/265 [00:00<00:00, 1083.77it/s]
2026-05-20:03:29:50 INFO     [api.task:312] Building contexts for mmlu_college_medicine on rank 0...

  0%|          | 0/173 [00:00<?, ?it/s]
100%|██████████| 173/173 [00:00<00:00, 1098.13it/s]
2026-05-20:03:29:50 INFO     [api.task:312] Building contexts for mmlu_global_facts on rank 0...

  0%|          | 0/100 [00:00<?, ?it/s]
100%|██████████| 100/100 [00:00<00:00, 1082.64it/s]
2026-05-20:03:29:50 INFO     [api.task:312] Building contexts for mmlu_human_aging on rank 0...

  0%|          | 0/223 [00:00<?, ?it/s]
100%|██████████| 223/223 [00:00<00:00, 1094.13it/s]
2026-05-20:03:29:50 INFO     [api.task:312] Building contexts for mmlu_management on rank 0...

  0%|          | 0/103 [00:00<?, ?it/s]
100%|██████████| 103/103 [00:00<00:00, 1084.46it/s]
2026-05-20:03:29:50 INFO     [api.task:312] Building contexts for mmlu_marketing on rank 0...

  0%|          | 0/234 [00:00<?, ?it/s]
100%|██████████| 234/234 [00:00<00:00, 1090.02it/s]
2026-05-20:03:29:50 INFO     [api.task:312] Building contexts for mmlu_medical_genetics on rank 0...

  0%|          | 0/100 [00:00<?, ?it/s]
100%|██████████| 100/100 [00:00<00:00, 1098.85it/s]
2026-05-20:03:29:51 INFO     [api.task:312] Building contexts for mmlu_miscellaneous on rank 0...

  0%|          | 0/783 [00:00<?, ?it/s]
100%|██████████| 783/783 [00:00<00:00, 1028.52it/s]
2026-05-20:03:29:51 INFO     [api.task:312] Building contexts for mmlu_nutrition on rank 0...

  0%|          | 0/306 [00:00<?, ?it/s]
100%|██████████| 306/306 [00:00<00:00, 1044.46it/s]
2026-05-20:03:29:52 INFO     [api.task:312] Building contexts for mmlu_professional_accounting on rank 0...

  0%|          | 0/282 [00:00<?, ?it/s]
100%|██████████| 282/282 [00:00<00:00, 961.32it/s]
2026-05-20:03:29:52 INFO     [api.task:312] Building contexts for mmlu_professional_medicine on rank 0...

  0%|          | 0/272 [00:00<?, ?it/s]
100%|██████████| 272/272 [00:00<00:00, 936.63it/s]
2026-05-20:03:29:52 INFO     [api.task:312] Building contexts for mmlu_virology on rank 0...

  0%|          | 0/166 [00:00<?, ?it/s]
100%|██████████| 166/166 [00:00<00:00, 932.97it/s]
2026-05-20:03:29:52 INFO     [api.task:312] Building contexts for mmlu_econometrics on rank 0...

  0%|          | 0/114 [00:00<?, ?it/s]
100%|██████████| 114/114 [00:00<00:00, 960.29it/s]
2026-05-20:03:29:53 INFO     [api.task:312] Building contexts for mmlu_high_school_geography on rank 0...

  0%|          | 0/198 [00:00<?, ?it/s]
100%|██████████| 198/198 [00:00<00:00, 985.45it/s]
2026-05-20:03:29:53 INFO     [api.task:312] Building contexts for mmlu_high_school_government_and_politics on rank 0...

  0%|          | 0/193 [00:00<?, ?it/s]
100%|██████████| 193/193 [00:00<00:00, 967.10it/s]
2026-05-20:03:29:53 INFO     [api.task:312] Building contexts for mmlu_high_school_macroeconomics on rank 0...

  0%|          | 0/390 [00:00<?, ?it/s]
100%|██████████| 390/390 [00:00<00:00, 982.08it/s]
2026-05-20:03:29:53 INFO     [api.task:312] Building contexts for mmlu_high_school_microeconomics on rank 0...

  0%|          | 0/238 [00:00<?, ?it/s]
100%|██████████| 238/238 [00:00<00:00, 962.24it/s]
2026-05-20:03:29:54 INFO     [api.task:312] Building contexts for mmlu_high_school_psychology on rank 0...

  0%|          | 0/545 [00:00<?, ?it/s]
100%|██████████| 545/545 [00:00<00:00, 1022.56it/s]
2026-05-20:03:29:54 INFO     [api.task:312] Building contexts for mmlu_human_sexuality on rank 0...

  0%|          | 0/131 [00:00<?, ?it/s]
100%|██████████| 131/131 [00:00<00:00, 961.17it/s]
2026-05-20:03:29:54 INFO     [api.task:312] Building contexts for mmlu_professional_psychology on rank 0...

  0%|          | 0/612 [00:00<?, ?it/s]
100%|██████████| 612/612 [00:00<00:00, 1064.10it/s]
2026-05-20:03:29:55 INFO     [api.task:312] Building contexts for mmlu_public_relations on rank 0...

  0%|          | 0/110 [00:00<?, ?it/s]
100%|██████████| 110/110 [00:00<00:00, 1000.19it/s]
2026-05-20:03:29:55 INFO     [api.task:312] Building contexts for mmlu_security_studies on rank 0...

  0%|          | 0/245 [00:00<?, ?it/s]
100%|██████████| 245/245 [00:00<00:00, 1007.10it/s]
2026-05-20:03:29:55 INFO     [api.task:312] Building contexts for mmlu_sociology on rank 0...

  0%|          | 0/201 [00:00<?, ?it/s]
100%|██████████| 201/201 [00:00<00:00, 1015.07it/s]
2026-05-20:03:29:55 INFO     [api.task:312] Building contexts for mmlu_us_foreign_policy on rank 0...

  0%|          | 0/100 [00:00<?, ?it/s]
100%|██████████| 100/100 [00:00<00:00, 1028.34it/s]
2026-05-20:03:29:56 INFO     [api.task:312] Building contexts for mmlu_formal_logic on rank 0...

  0%|          | 0/126 [00:00<?, ?it/s]
100%|██████████| 126/126 [00:00<00:00, 985.99it/s]
2026-05-20:03:29:56 INFO     [api.task:312] Building contexts for mmlu_high_school_european_history on rank 0...

  0%|          | 0/165 [00:00<?, ?it/s]
100%|██████████| 165/165 [00:00<00:00, 1098.78it/s]
2026-05-20:03:29:56 INFO     [api.task:312] Building contexts for mmlu_high_school_us_history on rank 0...

  0%|          | 0/204 [00:00<?, ?it/s]
100%|██████████| 204/204 [00:00<00:00, 1082.91it/s]
2026-05-20:03:29:56 INFO     [api.task:312] Building contexts for mmlu_high_school_world_history on rank 0...

  0%|          | 0/237 [00:00<?, ?it/s]
100%|██████████| 237/237 [00:00<00:00, 1094.28it/s]
2026-05-20:03:29:56 INFO     [api.task:312] Building contexts for mmlu_international_law on rank 0...

  0%|          | 0/121 [00:00<?, ?it/s]
100%|██████████| 121/121 [00:00<00:00, 1037.05it/s]
2026-05-20:03:29:56 INFO     [api.task:312] Building contexts for mmlu_jurisprudence on rank 0...

  0%|          | 0/108 [00:00<?, ?it/s]
100%|██████████| 108/108 [00:00<00:00, 1082.95it/s]
2026-05-20:03:29:56 INFO     [api.task:312] Building contexts for mmlu_logical_fallacies on rank 0...

  0%|          | 0/163 [00:00<?, ?it/s]
100%|██████████| 163/163 [00:00<00:00, 1091.56it/s]
2026-05-20:03:29:57 INFO     [api.task:312] Building contexts for mmlu_moral_disputes on rank 0...

  0%|          | 0/346 [00:00<?, ?it/s]
100%|██████████| 346/346 [00:00<00:00, 1077.49it/s]
2026-05-20:03:29:57 INFO     [api.task:312] Building contexts for mmlu_moral_scenarios on rank 0...

  0%|          | 0/895 [00:00<?, ?it/s]
100%|██████████| 895/895 [00:00<00:00, 1086.42it/s]
2026-05-20:03:29:58 INFO     [api.task:312] Building contexts for mmlu_philosophy on rank 0...

  0%|          | 0/311 [00:00<?, ?it/s]
100%|██████████| 311/311 [00:00<00:00, 1085.27it/s]
2026-05-20:03:29:58 INFO     [api.task:312] Building contexts for mmlu_prehistory on rank 0...

  0%|          | 0/324 [00:00<?, ?it/s]
100%|██████████| 324/324 [00:00<00:00, 1078.46it/s]
2026-05-20:03:29:58 INFO     [api.task:312] Building contexts for mmlu_professional_law on rank 0...

  0%|          | 0/1534 [00:00<?, ?it/s]
100%|██████████| 1534/1534 [00:01<00:00, 1068.90it/s]
2026-05-20:03:30:00 INFO     [api.task:312] Building contexts for mmlu_world_religions on rank 0...

  0%|          | 0/171 [00:00<?, ?it/s]
100%|██████████| 171/171 [00:00<00:00, 1077.00it/s]
2026-05-20:03:30:00 INFO     [api.task:312] Building contexts for hellaswag on rank 0...

  0%|          | 0/10042 [00:00<?, ?it/s]
100%|██████████| 10042/10042 [00:05<00:00, 1980.61it/s]
2026-05-20:03:30:06 INFO     [evaluator:585] Running loglikelihood requests

Tokenizing inputs:   0%|          | 0/100012 [00:00<?, ?it/s]
Tokenizing inputs: 100%|██████████| 100012/100012 [00:41<00:00, 2412.79it/s]

Running loglikelihood requests:   0%|          | 0/100012 [00:00<?, ?it/s]

Process still running.

### [2026-05-20 03:30:56 UTC] ASSISTANT

**Thinking**

The evaluation is still running. Let me wait more.

**Tool call:** `process`

```json
{
  "action": "poll",
  "sessionId": "briny-otter",
  "timeout": 600000
}
```

### [2026-05-20 03:32:56 UTC] TOOL RESULT
**Tool:** `process` | **Status:** `running`

Running loglikelihood requests:  19%|█▉        | 18953/100012 [02:00<08:33, 157.83it/s]

Process still running.

### [2026-05-20 03:33:01 UTC] ASSISTANT

**Thinking**

Still running. Let me wait more.

**Tool call:** `process`

```json
{
  "action": "poll",
  "sessionId": "briny-otter",
  "timeout": 600000
}
```

### [2026-05-20 03:35:01 UTC] TOOL RESULT
**Tool:** `process` | **Status:** `running`

Running loglikelihood requests:  20%|██        | 20429/100012 [02:15<08:24, 157.83it/s]
Running loglikelihood requests:  29%|██▊       | 28666/100012 [04:00<10:33, 112.55it/s]

Process still running.

### [2026-05-20 03:35:08 UTC] ASSISTANT

**Thinking**

It's making progress but slowly. The loglikelihood requests are running. Let me wait more.

**Tool call:** `process`

```json
{
  "action": "poll",
  "sessionId": "briny-otter",
  "timeout": 600000
}
```

### [2026-05-20 03:37:08 UTC] TOOL RESULT
**Tool:** `process` | **Status:** `running`

Running loglikelihood requests:  30%|██▉       | 29777/100012 [04:15<10:24, 112.55it/s]
Running loglikelihood requests:  38%|███▊      | 37787/100012 [06:00<10:49, 95.87it/s] 
Running loglikelihood requests:  39%|███▉      | 38900/100012 [06:15<10:37, 95.87it/s]

Process still running.

### [2026-05-20 03:37:14 UTC] ASSISTANT

**Thinking**

It's still running. Let me keep waiting. At this rate it'll take a while. Let me poll again.

**Tool call:** `process`

```json
{
  "action": "poll",
  "sessionId": "briny-otter",
  "timeout": 600000
}
```

### [2026-05-20 03:39:14 UTC] TOOL RESULT
**Tool:** `process` | **Status:** `running`

Running loglikelihood requests:  47%|████▋     | 46719/100012 [08:00<10:09, 87.40it/s]
Running loglikelihood requests:  48%|████▊     | 47969/100012 [08:15<09:55, 87.40it/s]

Process still running.

### [2026-05-20 03:39:18 UTC] ASSISTANT

**Thinking**

Still running, let me continue polling.

**Tool call:** `process`

```json
{
  "action": "poll",
  "sessionId": "briny-otter",
  "timeout": 600000
}
```

### [2026-05-20 03:41:18 UTC] TOOL RESULT
**Tool:** `process` | **Status:** `running`

Running loglikelihood requests:  57%|█████▋    | 56819/100012 [10:00<08:20, 86.22it/s]
Running loglikelihood requests:  58%|█████▊    | 58105/100012 [10:15<08:06, 86.22it/s]

Process still running.

### [2026-05-20 03:41:23 UTC] ASSISTANT

**Thinking**

Still running. Let me wait more.

**Tool call:** `process`

```json
{
  "action": "poll",
  "sessionId": "briny-otter",
  "timeout": 600000
}
```

### [2026-05-20 03:43:23 UTC] TOOL RESULT
**Tool:** `process` | **Status:** `running`

Running loglikelihood requests:  71%|███████   | 70705/100012 [12:00<05:04, 96.23it/s]
Running loglikelihood requests:  73%|███████▎  | 73069/100012 [12:15<04:39, 96.23it/s]

Process still running.

### [2026-05-20 03:43:27 UTC] ASSISTANT

**Thinking**

Let me continue polling.

**Tool call:** `process`

```json
{
  "action": "poll",
  "sessionId": "briny-otter",
  "timeout": 600000
}
```

### [2026-05-20 03:45:27 UTC] TOOL RESULT
**Tool:** `process` | **Status:** `running`

Running loglikelihood requests:  87%|████████▋ | 86709/100012 [14:00<02:02, 108.33it/s]
Running loglikelihood requests:  88%|████████▊ | 87946/100012 [14:15<01:51, 108.33it/s]

Process still running.

### [2026-05-20 03:45:30 UTC] ASSISTANT

**Thinking**

Almost done with loglikelihood. Let me continue waiting.

**Tool call:** `process`

```json
{
  "action": "poll",
  "sessionId": "briny-otter",
  "timeout": 600000
}
```

### [2026-05-20 03:47:30 UTC] TOOL RESULT
**Tool:** `process` | **Status:** `running`

Running loglikelihood requests:  94%|█████████▍| 94476/100012 [16:00<00:58, 94.43it/s] 
Running loglikelihood requests:  95%|█████████▌| 95339/100012 [16:15<00:49, 94.43it/s]

Process still running.

### [2026-05-20 03:47:34 UTC] ASSISTANT

**Thinking**

Let me keep waiting.

**Tool call:** `process`

```json
{
  "action": "poll",
  "sessionId": "briny-otter",
  "timeout": 600000
}
```

### [2026-05-20 03:48:33 UTC] TOOL RESULT
**Tool:** `process` | **Status:** `completed` | **Exit code:** `0`

Running loglikelihood requests: 100%|██████████| 100012/100012 [17:36<00:00, 94.64it/s]
fatal: not a git repository (or any of the parent directories): .git
2026-05-20:03:48:31 INFO     [loggers.evaluation_tracker:247] Saving results aggregated
hf ({'pretrained': '/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4', 'dtype': 'bfloat16', 'device_map': 'auto'}), gen_kwargs: ({'max_gen_toks': 2048}), limit: None, num_fewshot: None, batch_size: 8
|                 Tasks                 |Version|Filter|n-shot| Metric |   |Value |   |Stderr|
|---------------------------------------|------:|------|-----:|--------|---|-----:|---|-----:|
|mmlu                                   |      2|none  |      |acc     |   |0.3017|±  |0.0039|
| - humanities                          |      2|none  |     0|acc     |↑  |0.2854|±  |0.0066|
|  - formal_logic                       |      1|none  |     0|acc     |↑  |0.3095|±  |0.0413|
|  - high_school_european_history       |      1|none  |     0|acc     |↑  |0.3636|±  |0.0376|
|  - high_school_us_history             |      1|none  |     0|acc     |↑  |0.3480|±  |0.0334|
|  - high_school_world_history          |      1|none  |     0|acc     |↑  |0.3291|±  |0.0306|
|  - international_law                  |      1|none  |     0|acc     |↑  |0.2562|±  |0.0398|
|  - jurisprudence                      |      1|none  |     0|acc     |↑  |0.3241|±  |0.0452|
|  - logical_fallacies                  |      1|none  |     0|acc     |↑  |0.2822|±  |0.0354|
|  - moral_disputes                     |      1|none  |     0|acc     |↑  |0.3266|±  |0.0252|
|  - moral_scenarios                    |      1|none  |     0|acc     |↑  |0.2324|±  |0.0141|
|  - philosophy                         |      1|none  |     0|acc     |↑  |0.2862|±  |0.0257|
|  - prehistory                         |      1|none  |     0|acc     |↑  |0.2932|±  |0.0253|
|  - professional_law                   |      1|none  |     0|acc     |↑  |0.2751|±  |0.0114|
|  - world_religions                    |      1|none  |     0|acc     |↑  |0.3275|±  |0.0360|
| - other                               |      2|none  |     0|acc     |↑  |0.3119|±  |0.0083|
|  - business_ethics                    |      1|none  |     0|acc     |↑  |0.3600|±  |0.0482|
|  - clinical_knowledge                 |      1|none  |     0|acc     |↑  |0.3132|±  |0.0285|
|  - college_medicine                   |      1|none  |     0|acc     |↑  |0.3295|±  |0.0358|
|  - global_facts                       |      1|none  |     0|acc     |↑  |0.2900|±  |0.0456|
|  - human_aging                        |      1|none  |     0|acc     |↑  |0.2646|±  |0.0296|
|  - management                         |      1|none  |     0|acc     |↑  |0.3495|±  |0.0472|
|  - marketing                          |      1|none  |     0|acc     |↑  |0.3803|±  |0.0318|
|  - medical_genetics                   |      1|none  |     0|acc     |↑  |0.3100|±  |0.0465|
|  - miscellaneous                      |      1|none  |     0|acc     |↑  |0.2912|±  |0.0162|
|  - nutrition                          |      1|none  |     0|acc     |↑  |0.3627|±  |0.0275|
|  - professional_accounting            |      1|none  |     0|acc     |↑  |0.2766|±  |0.0267|
|  - professional_medicine              |      1|none  |     0|acc     |↑  |0.3015|±  |0.0279|
|  - virology                           |      1|none  |     0|acc     |↑  |0.3012|±  |0.0357|
| - social sciences                     |      2|none  |     0|acc     |↑  |0.3211|±  |0.0084|
|  - econometrics                       |      1|none  |     0|acc     |↑  |0.2807|±  |0.0423|
|  - high_school_geography              |      1|none  |     0|acc     |↑  |0.3788|±  |0.0346|
|  - high_school_government_and_politics|      1|none  |     0|acc     |↑  |0.3316|±  |0.0340|
|  - high_school_macroeconomics         |      1|none  |     0|acc     |↑  |0.2846|±  |0.0229|
|  - high_school_microeconomics         |      1|none  |     0|acc     |↑  |0.3277|±  |0.0305|
|  - high_school_psychology             |      1|none  |     0|acc     |↑  |0.3431|±  |0.0204|
|  - human_sexuality                    |      1|none  |     0|acc     |↑  |0.3893|±  |0.0428|
|  - professional_psychology            |      1|none  |     0|acc     |↑  |0.2729|±  |0.0180|
|  - public_relations                   |      1|none  |     0|acc     |↑  |0.2545|±  |0.0417|
|  - security_studies                   |      1|none  |     0|acc     |↑  |0.3020|±  |0.0294|
|  - sociology                          |      1|none  |     0|acc     |↑  |0.3731|±  |0.0342|
|  - us_foreign_policy                  |      1|none  |     0|acc     |↑  |0.4600|±  |0.0501|
| - stem                                |      2|none  |     0|acc     |↑  |0.2972|±  |0.0081|
|  - abstract_algebra                   |      1|none  |     0|acc     |↑  |0.3100|±  |0.0465|
|  - anatomy                            |      1|none  |     0|acc     |↑  |0.3185|±  |0.0402|
|  - astronomy                          |      1|none  |     0|acc     |↑  |0.2895|±  |0.0369|
|  - college_biology                    |      1|none  |     0|acc     |↑  |0.2639|±  |0.0369|
|  - college_chemistry                  |      1|none  |     0|acc     |↑  |0.2700|±  |0.0446|
|  - college_computer_science           |      1|none  |     0|acc     |↑  |0.3400|±  |0.0476|
|  - college_mathematics                |      1|none  |     0|acc     |↑  |0.3300|±  |0.0473|
|  - college_physics                    |      1|none  |     0|acc     |↑  |0.3235|±  |0.0466|
|  - computer_security                  |      1|none  |     0|acc     |↑  |0.3900|±  |0.0490|
|  - conceptual_physics                 |      1|none  |     0|acc     |↑  |0.2936|±  |0.0298|
|  - electrical_engineering             |      1|none  |     0|acc     |↑  |0.3724|±  |0.0403|
|  - elementary_mathematics             |      1|none  |     0|acc     |↑  |0.2487|±  |0.0223|
|  - high_school_biology                |      1|none  |     0|acc     |↑  |0.3194|±  |0.0265|
|  - high_school_chemistry              |      1|none  |     0|acc     |↑  |0.2759|±  |0.0314|
|  - high_school_computer_science       |      1|none  |     0|acc     |↑  |0.2800|±  |0.0451|
|  - high_school_mathematics            |      1|none  |     0|acc     |↑  |0.2852|±  |0.0275|
|  - high_school_physics                |      1|none  |     0|acc     |↑  |0.2450|±  |0.0351|
|  - high_school_statistics             |      1|none  |     0|acc     |↑  |0.2917|±  |0.0310|
|  - machine_learning                   |      1|none  |     0|acc     |↑  |0.3393|±  |0.0449|
|hellaswag                              |      1|none  |     0|acc     |↑  |0.3321|±  |0.0047|
|                                       |       |none  |     0|acc_norm|↑  |0.4017|±  |0.0049|
|piqa                                   |      1|none  |     0|acc     |↑  |0.6219|±  |0.0113|
|                                       |       |none  |     0|acc_norm|↑  |0.6186|±  |0.0113|

|      Groups      |Version|Filter|n-shot|Metric|   |Value |   |Stderr|
|------------------|------:|------|-----:|------|---|-----:|---|-----:|
|mmlu              |      2|none  |      |acc   |   |0.3017|±  |0.0039|
| - humanities     |      2|none  |     0|acc   |↑  |0.2854|±  |0.0066|
| - other          |      2|none  |     0|acc   |↑  |0.3119|±  |0.0083|
| - social sciences|      2|none  |     0|acc   |↑  |0.3211|±  |0.0084|
| - stem           |      2|none  |     0|acc   |↑  |0.2972|±  |0.0081|

Process exited with code 0.

### [2026-05-20 03:48:41 UTC] ASSISTANT

**Thinking**

The evaluation completed successfully. Now let me parse the results and create the accuracy.json file.

Results from the output:
- mmlu: acc = 0.3017, stderr = 0.0039
- hellaswag: acc = 0.3321, acc_norm = 0.4017 (we use acc = 0.3321)
- piqa: acc = 0.6219, acc_norm = 0.6186 (we use acc = 0.6219)

Let me now look at the raw results file to get the exact values.

The evaluation completed. Now let me parse the results and create accuracy.json:


**Tool call:** `exec`

```json
{
  "command": "ls /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/lm_eval_results/\nfind /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/lm_eval_results/ -name \"results_*.json\" 2>/dev/null"
}
```

### [2026-05-20 03:48:41 UTC] TOOL RESULT
**Tool:** `exec` | **Status:** `completed` | **Exit code:** `0`

__root__.openclaw__workspace__quantized__Qwen_Qwen2.5-0.5B-MXFP4
/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/lm_eval_results/__root__.openclaw__workspace__quantized__Qwen_Qwen2.5-0.5B-MXFP4/results_2026-05-20T03-48-31.946238.json

### [2026-05-20 03:48:46 UTC] ASSISTANT

**Thinking**

Let me read the results JSON file.

**Tool call:** `exec`

```json
{
  "command": "VENV_PY=\"/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/bin/python\"\nRESULTS_FILE=\"/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/lm_eval_results/__root__.openclaw__workspace__quantized__Qwen_Qwen2.5-0.5B-MXFP4/results_2026-05-20T03-48-31.946238.json\"\n\n$VENV_PY - << 'EOF'\nimport json, sys\nresults_file = \"/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/lm_eval_results/__root__.openclaw__workspace__quantized__Qwen_Qwen2.5-0.5B-MXFP4/results_2026-05-20T03-48-31.946238.json\"\nwith open(results_file) as f:\n    data = json.load(f)\n\n# Extract results\ntasks = [\"piqa\", \"mmlu\", \"hellaswag\"]\nfor task in tasks:\n    if task in data[\"results\"]:\n        res = data[\"results\"][task]\n        print(f\"\\n=== {task} ===\")\n        for k, v in res.items():\n            if isinstance(v, dict):\n                for k2, v2 in v.items():\n                    print(f\"  {k}.{k2}: {v2}\")\n            else:\n                print(f\"  {k}: {v}\")\nEOF"
}
```

### [2026-05-20 03:48:47 UTC] TOOL RESULT
**Tool:** `exec` | **Status:** `completed` | **Exit code:** `0`

=== piqa ===
  name: piqa
  alias: piqa
  sample_len: 1838
  acc,none: 0.6218715995647442
  acc_stderr,none: 0.011313980666854472
  acc_norm,none: 0.6186071817192601
  acc_norm_stderr,none: 0.01133285040652847

=== mmlu ===
  alias: mmlu
  name: mmlu
  sample_len: 14042
  acc,none: 0.3017376442102265
  acc_stderr,none: 0.0038659889626461315
  sample_count.acc,none: 14042

=== hellaswag ===
  name: hellaswag
  alias: hellaswag
  sample_len: 10042
  acc,none: 0.33210515833499304
  acc_stderr,none: 0.004700059671374276
  acc_norm,none: 0.4017128062139016
  acc_norm_stderr,none: 0.00489242535637569

### [2026-05-20 03:48:51 UTC] ASSISTANT

**Thinking**

Now let me get the duration from the logs and create the accuracy.json.

**Tool call:** `exec`

```json
{
  "command": "grep -E \"Running for|Total elapsed\" /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/logs/eval_exec.log | tail -5\ngrep -E \"elapsed|duration|seconds|Time\" /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/logs/eval_exec.log | tail -10"
}
```

### [2026-05-20 03:48:51 UTC] TOOL RESULT
**Tool:** `exec` | **Status:** `completed` | **Exit code:** `0`

(no output)

### [2026-05-20 03:48:53 UTC] ASSISTANT

**Thinking**

Let me look at the log file to find the timing information.

**Tool call:** `exec`

```json
{
  "command": "tail -50 /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/logs/eval_exec.log"
}
```

### [2026-05-20 03:48:53 UTC] TOOL RESULT
**Tool:** `exec` | **Status:** `completed` | **Exit code:** `0`

|  - nutrition                          |      1|none  |     0|acc     |↑  |0.3627|±  |0.0275|
|  - professional_accounting            |      1|none  |     0|acc     |↑  |0.2766|±  |0.0267|
|  - professional_medicine              |      1|none  |     0|acc     |↑  |0.3015|±  |0.0279|
|  - virology                           |      1|none  |     0|acc     |↑  |0.3012|±  |0.0357|
| - social sciences                     |      2|none  |     0|acc     |↑  |0.3211|±  |0.0084|
|  - econometrics                       |      1|none  |     0|acc     |↑  |0.2807|±  |0.0423|
|  - high_school_geography              |      1|none  |     0|acc     |↑  |0.3788|±  |0.0346|
|  - high_school_government_and_politics|      1|none  |     0|acc     |↑  |0.3316|±  |0.0340|
|  - high_school_macroeconomics         |      1|none  |     0|acc     |↑  |0.2846|±  |0.0229|
|  - high_school_microeconomics         |      1|none  |     0|acc     |↑  |0.3277|±  |0.0305|
|  - high_school_psychology             |      1|none  |     0|acc     |↑  |0.3431|±  |0.0204|
|  - human_sexuality                    |      1|none  |     0|acc     |↑  |0.3893|±  |0.0428|
|  - professional_psychology            |      1|none  |     0|acc     |↑  |0.2729|±  |0.0180|
|  - public_relations                   |      1|none  |     0|acc     |↑  |0.2545|±  |0.0417|
|  - security_studies                   |      1|none  |     0|acc     |↑  |0.3020|±  |0.0294|
|  - sociology                          |      1|none  |     0|acc     |↑  |0.3731|±  |0.0342|
|  - us_foreign_policy                  |      1|none  |     0|acc     |↑  |0.4600|±  |0.0501|
| - stem                                |      2|none  |     0|acc     |↑  |0.2972|±  |0.0081|
|  - abstract_algebra                   |      1|none  |     0|acc     |↑  |0.3100|±  |0.0465|
|  - anatomy                            |      1|none  |     0|acc     |↑  |0.3185|±  |0.0402|
|  - astronomy                          |      1|none  |     0|acc     |↑  |0.2895|±  |0.0369|
|  - college_biology                    |      1|none  |     0|acc     |↑  |0.2639|±  |0.0369|
|  - college_chemistry                  |      1|none  |     0|acc     |↑  |0.2700|±  |0.0446|
|  - college_computer_science           |      1|none  |     0|acc     |↑  |0.3400|±  |0.0476|
|  - college_mathematics                |      1|none  |     0|acc     |↑  |0.3300|±  |0.0473|
|  - college_physics                    |      1|none  |     0|acc     |↑  |0.3235|±  |0.0466|
|  - computer_security                  |      1|none  |     0|acc     |↑  |0.3900|±  |0.0490|
|  - conceptual_physics                 |      1|none  |     0|acc     |↑  |0.2936|±  |0.0298|
|  - electrical_engineering             |      1|none  |     0|acc     |↑  |0.3724|±  |0.0403|
|  - elementary_mathematics             |      1|none  |     0|acc     |↑  |0.2487|±  |0.0223|
|  - high_school_biology                |      1|none  |     0|acc     |↑  |0.3194|±  |0.0265|
|  - high_school_chemistry              |      1|none  |     0|acc     |↑  |0.2759|±  |0.0314|
|  - high_school_computer_science       |      1|none  |     0|acc     |↑  |0.2800|±  |0.0451|
|  - high_school_mathematics            |      1|none  |     0|acc     |↑  |0.2852|±  |0.0275|
|  - high_school_physics                |      1|none  |     0|acc     |↑  |0.2450|±  |0.0351|
|  - high_school_statistics             |      1|none  |     0|acc     |↑  |0.2917|±  |0.0310|
|  - machine_learning                   |      1|none  |     0|acc     |↑  |0.3393|±  |0.0449|
|hellaswag                              |      1|none  |     0|acc     |↑  |0.3321|±  |0.0047|
|                                       |       |none  |     0|acc_norm|↑  |0.4017|±  |0.0049|
|piqa                                   |      1|none  |     0|acc     |↑  |0.6219|±  |0.0113|
|                                       |       |none  |     0|acc_norm|↑  |0.6186|±  |0.0113|

|      Groups      |Version|Filter|n-shot|Metric|   |Value |   |Stderr|
|------------------|------:|------|-----:|------|---|-----:|---|-----:|
|mmlu              |      2|none  |      |acc   |   |0.3017|±  |0.0039|
| - humanities     |      2|none  |     0|acc   |↑  |0.2854|±  |0.0066|
| - other          |      2|none  |     0|acc   |↑  |0.3119|±  |0.0083|
| - social sciences|      2|none  |     0|acc   |↑  |0.3211|±  |0.0084|
| - stem           |      2|none  |     0|acc   |↑  |0.2972|±  |0.0081|

### [2026-05-20 03:48:57 UTC] ASSISTANT

**Thinking**

Let me look at the log for the timestamp at the start of the evaluation to calculate the duration.

**Tool call:** `exec`

```json
{
  "command": "head -20 /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/logs/eval_exec.log"
}
```

### [2026-05-20 03:48:57 UTC] TOOL RESULT
**Tool:** `exec` | **Status:** `completed` | **Exit code:** `0`

2026-05-20:03:28:47 INFO     [_cli.run:388] Selected Tasks: ['piqa', 'mmlu', 'hellaswag']
2026-05-20:03:28:48 INFO     [evaluator:214] Setting random seed to 0 | Setting numpy seed to 1234 | Setting torch manual seed to 1234 | Setting fewshot manual seed to 1234
2026-05-20:03:28:48 WARNING  [evaluator:226] generation_kwargs: {'max_gen_toks': 2048} specified through cli, these settings will update set parameters in yaml tasks. Ensure 'do_sample=True' for non-greedy decoding!
2026-05-20:03:28:48 INFO     [evaluator:239] Initializing hf model, with arguments: {'pretrained': '/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4', 'dtype': 'bfloat16', 'device_map': 'auto', 'trust_remote_code': True}
2026-05-20:03:28:52 INFO     [models.huggingface:286] Using device 'cuda'
2026-05-20:03:28:53 INFO     [models.huggingface:585] Model parallel was set to False.
/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/transformers/quantizers/auto.py:262: UserWarning: You passed `quantization_config` or equivalent parameters to `from_pretrained` but the model you're loading already has a `quantization_config` attribute. The `quantization_config` from the model will be used.However, loading attributes (e.g. ['backend']) will be overwritten with the one you passed to `from_pretrained`. The rest will be ignored.
  warnings.warn(warning_msg)
[33;1m2026-05-20 03:28:53 WARNING modeling_utils.py L4555: `loss_type=None` was set in the config but it is unrecognized. Using the default loss: `ForCausalLMLoss`.[0m
[33;1m2026-05-20 03:28:53 WARNING mx.py L162: MXFP quantization is still in experimental stage, the inference speed might be slow.[0m
Warning: You are sending unauthenticated requests to the HF Hub. Please set a HF_TOKEN to enable higher rate limits and faster downloads.

Generating train split:   0%|          | 0/16113 [00:00<?, ? examples/s]
Generating train split: 100%|██████████| 16113/16113 [00:00<00:00, 1023439.39 examples/s]

Generating validation split:   0%|          | 0/1838 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 1838/1838 [00:00<00:00, 792712.67 examples/s]

Generating test split:   0%|          | 0/3084 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 3084/3084 [00:00<00:00, 1081270.04 examples/s]

Generating test split:   0%|          | 0/100 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 100/100 [00:00<00:00, 32809.01 examples/s]

Generating validation split:   0%|          | 0/11 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 11/11 [00:00<00:00, 5641.64 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 3181.36 examples/s]

Generating test split:   0%|          | 0/135 [00:00<?, ? examples/s]
Generating test split: 100%|██████████| 135/135 [00:00<00:00, 50038.09 examples/s]

Generating validation split:   0%|          | 0/14 [00:00<?, ? examples/s]
Generating validation split: 100%|██████████| 14/14 [00:00<00:00, 7127.97 examples/s]

Generating dev split:   0%|          | 0/5 [00:00<?, ? examples/s]
Generating dev split: 100%|██████████| 5/5 [00:00<00:00, 2667.11 examples/s]

### [2026-05-20 03:49:02 UTC] ASSISTANT

**Thinking**

Let me look at the last few lines of the log for the timing.

**Tool call:** `exec`

```json
{
  "command": "# Calculate duration from timestamps\n# Started: 2026-05-20:03:28:47\n# Ended: last log entries show the results\n# Let me look at the very end of the log for a final timestamp\n\ngrep -E \"^\\d{4}-\\d{2}-\\d{2}:\" /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/logs/eval_exec.log | tail -5"
}
```

### [2026-05-20 03:49:02 UTC] TOOL RESULT
**Tool:** `exec` | **Status:** `completed` | **Exit code:** `0`

(no output)

### [2026-05-20 03:49:05 UTC] ASSISTANT

**Thinking**

The timestamps aren't in that format. Let me look at the raw log to find timing.

**Tool call:** `exec`

```json
{
  "command": "grep \"INFO\\|elapsed\\|runtime\\|duration\\|seconds\\|Time\\|total\" /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/logs/eval_exec.log | tail -20"
}
```

### [2026-05-20 03:49:05 UTC] TOOL RESULT
**Tool:** `exec` | **Status:** `completed` | **Exit code:** `0`

2026-05-20:03:29:55 INFO     [api.task:312] Building contexts for mmlu_public_relations on rank 0...
2026-05-20:03:29:55 INFO     [api.task:312] Building contexts for mmlu_security_studies on rank 0...
2026-05-20:03:29:55 INFO     [api.task:312] Building contexts for mmlu_sociology on rank 0...
2026-05-20:03:29:55 INFO     [api.task:312] Building contexts for mmlu_us_foreign_policy on rank 0...
2026-05-20:03:29:56 INFO     [api.task:312] Building contexts for mmlu_formal_logic on rank 0...
2026-05-20:03:29:56 INFO     [api.task:312] Building contexts for mmlu_high_school_european_history on rank 0...
2026-05-20:03:29:56 INFO     [api.task:312] Building contexts for mmlu_high_school_us_history on rank 0...
2026-05-20:03:29:56 INFO     [api.task:312] Building contexts for mmlu_high_school_world_history on rank 0...
2026-05-20:03:29:56 INFO     [api.task:312] Building contexts for mmlu_international_law on rank 0...
2026-05-20:03:29:56 INFO     [api.task:312] Building contexts for mmlu_jurisprudence on rank 0...
2026-05-20:03:29:56 INFO     [api.task:312] Building contexts for mmlu_logical_fallacies on rank 0...
2026-05-20:03:29:57 INFO     [api.task:312] Building contexts for mmlu_moral_disputes on rank 0...
2026-05-20:03:29:57 INFO     [api.task:312] Building contexts for mmlu_moral_scenarios on rank 0...
2026-05-20:03:29:58 INFO     [api.task:312] Building contexts for mmlu_philosophy on rank 0...
2026-05-20:03:29:58 INFO     [api.task:312] Building contexts for mmlu_prehistory on rank 0...
2026-05-20:03:29:58 INFO     [api.task:312] Building contexts for mmlu_professional_law on rank 0...
2026-05-20:03:30:00 INFO     [api.task:312] Building contexts for mmlu_world_religions on rank 0...
2026-05-20:03:30:00 INFO     [api.task:312] Building contexts for hellaswag on rank 0...
2026-05-20:03:30:06 INFO     [evaluator:585] Running loglikelihood requests
2026-05-20:03:48:31 INFO     [loggers.evaluation_tracker:247] Saving results aggregated

### [2026-05-20 03:49:12 UTC] ASSISTANT

**Thinking**

The log shows the evaluation started at 03:28:47 and ended at 03:48:31. That's approximately 19 minutes and 44 seconds. Let me compute this more precisely:

From 03:28:47 to 03:48:31:
- Minutes: 03:28 to 03:48 = 20 minutes
- But starting at 03:28:47 and ending at 03:48:31 = 19 minutes 44 seconds

Wait, that's not right. Let me recalculate:
- 03:28:47 to 03:48:31
- If we go from 03:28:47 to 03:48:47, that would be exactly 20 minutes.


- Since we stopped at 03:48:31, which is 16 seconds earlier, that gives us 19 minutes 44 seconds total, or about 1184 seconds.

Now I need to check if the results JSON contains timing information I can use instead.

**Tool call:** `exec`

```json
{
  "command": "cat /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/lm_eval_results/__root__.openclaw__workspace__quantized__Qwen_Qwen2.5-0.5B-MXFP4/results_2026-05-20T03-48-31.946238.json | python3 -c \"import json,sys; d=json.load(sys.stdin); print(json.dumps({k:v for k,v in d.items() if k != 'samples'}, indent=2))\""
}
```

### [2026-05-20 03:49:12 UTC] TOOL RESULT
**Tool:** `exec` | **Status:** `completed` | **Exit code:** `0`

{
  "results": {
    "piqa": {
      "name": "piqa",
      "alias": "piqa",
      "sample_len": 1838,
      "acc,none": 0.6218715995647442,
      "acc_stderr,none": 0.011313980666854472,
      "acc_norm,none": 0.6186071817192601,
      "acc_norm_stderr,none": 0.01133285040652847
    },
    "mmlu_abstract_algebra": {
      "name": "mmlu_abstract_algebra",
      "alias": "abstract_algebra",
      "sample_len": 100,
      "acc,none": 0.31,
      "acc_stderr,none": 0.04648231987117317
    },
    "mmlu_anatomy": {
      "name": "mmlu_anatomy",
      "alias": "anatomy",
      "sample_len": 135,
      "acc,none": 0.31851851851851853,
      "acc_stderr,none": 0.04024778401977107
    },
    "mmlu_astronomy": {
      "name": "mmlu_astronomy",
      "alias": "astronomy",
      "sample_len": 152,
      "acc,none": 0.2894736842105263,
      "acc_stderr,none": 0.03690677986137281
    },
    "mmlu_college_biology": {
      "name": "mmlu_college_biology",
      "alias": "college_biology",
      "sample_len": 144,
      "acc,none": 0.2638888888888889,
      "acc_stderr,none": 0.03685651095897531
    },
    "mmlu_college_chemistry": {
      "name": "mmlu_college_chemistry",
      "alias": "college_chemistry",
      "sample_len": 100,
      "acc,none": 0.27,
      "acc_stderr,none": 0.04461960433384737
    },
    "mmlu_college_computer_science": {
      "name": "mmlu_college_computer_science",
      "alias": "college_computer_science",
      "sample_len": 100,
      "acc,none": 0.34,
      "acc_stderr,none": 0.04760952285695233
    },
    "mmlu_college_mathematics": {
      "name": "mmlu_college_mathematics",
      "alias": "college_mathematics",
      "sample_len": 100,
      "acc,none": 0.33,
      "acc_stderr,none": 0.04725815626252609
    },
    "mmlu_college_physics": {
      "name": "mmlu_college_physics",
      "alias": "college_physics",
      "sample_len": 102,
      "acc,none": 0.3235294117647059,
      "acc_stderr,none": 0.04655010411319613
    },
    "mmlu_computer_security": {
      "name": "mmlu_computer_security",
      "alias": "computer_security",
      "sample_len": 100,
      "acc,none": 0.39,
      "acc_stderr,none": 0.04902071300001973
    },
    "mmlu_conceptual_physics": {
      "name": "mmlu_conceptual_physics",
      "alias": "conceptual_physics",
      "sample_len": 235,
      "acc,none": 0.2936170212765957,
      "acc_stderr,none": 0.02977164271249127
    },
    "mmlu_electrical_engineering": {
      "name": "mmlu_electrical_engineering",
      "alias": "electrical_engineering",
      "sample_len": 145,
      "acc,none": 0.3724137931034483,
      "acc_stderr,none": 0.0402873153294756
    },
    "mmlu_elementary_mathematics": {
      "name": "mmlu_elementary_mathematics",
      "alias": "elementary_mathematics",
      "sample_len": 378,
      "acc,none": 0.24867724867724866,
      "acc_stderr,none": 0.022261817692400182
    },
    "mmlu_high_school_biology": {
      "name": "mmlu_high_school_biology",
      "alias": "high_school_biology",
      "sample_len": 310,
      "acc,none": 0.3193548387096774,
      "acc_stderr,none": 0.026522709674667667
    },
    "mmlu_high_school_chemistry": {
      "name": "mmlu_high_school_chemistry",
      "alias": "high_school_chemistry",
      "sample_len": 203,
      "acc,none": 0.27586206896551724,
      "acc_stderr,none": 0.0314471258167824
    },
    "mmlu_high_school_computer_science": {
      "name": "mmlu_high_school_computer_science",
      "alias": "high_school_computer_science",
      "sample_len": 100,
      "acc,none": 0.28,
      "acc_stderr,none": 0.045126085985421296
    },
    "mmlu_high_school_mathematics": {
      "name": "mmlu_high_school_mathematics",
      "alias": "high_school_mathematics",
      "sample_len": 270,
      "acc,none": 0.2851851851851852,
      "acc_stderr,none": 0.02752859921034045
    },
    "mmlu_high_school_physics": {
      "name": "mmlu_high_school_physics",
      "alias": "high_school_physics",
      "sample_len": 151,
      "acc,none": 0.24503311258278146,
      "acc_stderr,none": 0.035118075718047294
    },
    "mmlu_high_school_statistics": {
      "name": "mmlu_high_school_statistics",
      "alias": "high_school_statistics",
      "sample_len": 216,
      "acc,none": 0.2916666666666667,
      "acc_stderr,none": 0.030998666304560565
    },
    "mmlu_machine_learning": {
      "name": "mmlu_machine_learning",
      "alias": "machine_learning",
      "sample_len": 112,
      "acc,none": 0.3392857142857143,
      "acc_stderr,none": 0.04493949068613541
    },
    "mmlu_business_ethics": {
      "name": "mmlu_business_ethics",
      "alias": "business_ethics",
      "sample_len": 100,
      "acc,none": 0.36,
      "acc_stderr,none": 0.048241815132442176
    },
    "mmlu_clinical_knowledge": {
      "name": "mmlu_clinical_knowledge",
      "alias": "clinical_knowledge",
      "sample_len": 265,
      "acc,none": 0.3132075471698113,
      "acc_stderr,none": 0.02854479331905527
    },
    "mmlu_college_medicine": {
      "name": "mmlu_college_medicine",
      "alias": "college_medicine",
      "sample_len": 173,
      "acc,none": 0.32947976878612717,
      "acc_stderr,none": 0.03583901754736415
    },
    "mmlu_global_facts": {
      "name": "mmlu_global_facts",
      "alias": "global_facts",
      "sample_len": 100,
      "acc,none": 0.29,
      "acc_stderr,none": 0.045604802157206865
    },
    "mmlu_human_aging": {
      "name": "mmlu_human_aging",
      "alias": "human_aging",
      "sample_len": 223,
      "acc,none": 0.2645739910313901,
      "acc_stderr,none": 0.029605103217038367
    },
    "mmlu_management": {
      "name": "mmlu_management",
      "alias": "management",
      "sample_len": 103,
      "acc,none": 0.34951456310679613,
      "acc_stderr,none": 0.047211885060971744
    },
    "mmlu_marketing": {
      "name": "mmlu_marketing",
      "alias": "marketing",
      "sample_len": 234,
      "acc,none": 0.3803418803418803,
      "acc_stderr,none": 0.031804252043841054
    },
    "mmlu_medical_genetics": {
      "name": "mmlu_medical_genetics",
      "alias": "medical_genetics",
      "sample_len": 100,
      "acc,none": 0.31,
      "acc_stderr,none": 0.04648231987117317
    },
    "mmlu_miscellaneous": {
      "name": "mmlu_miscellaneous",
      "alias": "miscellaneous",
      "sample_len": 783,
      "acc,none": 0.29118773946360155,
      "acc_stderr,none": 0.016246087069701313
    },
    "mmlu_nutrition": {
      "name": "mmlu_nutrition",
      "alias": "nutrition",
      "sample_len": 306,
      "acc,none": 0.3627450980392157,
      "acc_stderr,none": 0.02753007844711037
    },
    "mmlu_professional_accounting": {
      "name": "mmlu_professional_accounting",
      "alias": "professional_accounting",
      "sample_len": 282,
      "acc,none": 0.2765957446808511,
      "acc_stderr,none": 0.02668456434046097
    },
    "mmlu_professional_medicine": {
      "name": "mmlu_professional_medicine",
      "alias": "professional_medicine",
      "sample_len": 272,
      "acc,none": 0.3014705882352941,
      "acc_stderr,none": 0.027875982114273144
    },
    "mmlu_virology": {
      "name": "mmlu_virology",
      "alias": "virology",
      "sample_len": 166,
      "acc,none": 0.30120481927710846,
      "acc_stderr,none": 0.035716092300534796
    },
    "mmlu_econometrics": {
      "name": "mmlu_econometrics",
      "alias": "econometrics",
      "sample_len": 114,
      "acc,none": 0.2807017543859649,
      "acc_stderr,none": 0.042270544512322025
    },
    "mmlu_high_school_geography": {
      "name": "mmlu_high_school_geography",
      "alias": "high_school_geography",
      "sample_len": 198,
      "acc,none": 0.3787878787878788,
      "acc_stderr,none": 0.03456088731993742
    },
    "mmlu_high_school_government_and_politics": {
      "name": "mmlu_high_school_government_and_politics",
      "alias": "high_school_government_and_politics",
      "sample_len": 193,
      "acc,none": 0.3316062176165803,
      "acc_stderr,none": 0.0339763654108912
    },
    "mmlu_high_school_macroeconomics": {
      "name": "mmlu_high_school_macroeconomics",
      "alias": "high_school_macroeconomics",
      "sample_len": 390,
      "acc,none": 0.2846153846153846,
      "acc_stderr,none": 0.022878322799706304
    },
    "mmlu_high_school_microeconomics": {
      "name": "mmlu_high_school_microeconomics",
      "alias": "high_school_microeconomics",
      "sample_len": 238,
      "acc,none": 0.3277310924369748,
      "acc_stderr,none": 0.030489911417673238
    },
    "mmlu_high_school_psychology": {
      "name": "mmlu_high_school_psychology",
      "alias": "high_school_psychology",
      "sample_len": 545,
      "acc,none": 0.3431192660550459,
      "acc_stderr,none": 0.020354777736086044
    },
    "mmlu_human_sexuality": {
      "name": "mmlu_human_sexuality",
      "alias": "human_sexuality",
      "sample_len": 131,
      "acc,none": 0.3893129770992366,
      "acc_stderr,none": 0.042764865428145914
    },
    "mmlu_professional_psychology": {
      "name": "mmlu_professional_psychology",
      "alias": "professional_psychology",
      "sample_len": 612,
      "acc,none": 0.272875816993464,
      "acc_stderr,none": 0.01802047414839352
    },
    "mmlu_public_relations": {
      "name": "mmlu_public_relations",
      "alias": "public_relations",
      "sample_len": 110,
      "acc,none": 0.2545454545454545,
      "acc_stderr,none": 0.04172343038705381
    },
    "mmlu_security_studies": {
      "name": "mmlu_security_studies",
      "alias": "security_studies",
      "sample_len": 245,
      "acc,none": 0.3020408163265306,
      "acc_stderr,none": 0.029393609319879853
    },
    "mmlu_sociology": {
      "name": "mmlu_sociology",
      "alias": "sociology",
      "sample_len": 201,
      "acc,none": 0.373134328358209,
      "acc_stderr,none": 0.03419832608176
    },
    "mmlu_us_foreign_policy": {
      "name": "mmlu_us_foreign_policy",
      "alias": "us_foreign_policy",
      "sample_len": 100,
      "acc,none": 0.46,
      "acc_stderr,none": 0.05009082659620332
    },
    "mmlu_formal_logic": {
      "name": "mmlu_formal_logic",
      "alias": "formal_logic",
      "sample_len": 126,
      "acc,none": 0.30952380952380953,
      "acc_stderr,none": 0.04134913018303316
    },
    "mmlu_high_school_european_history": {
      "name": "mmlu_high_school_european_history",
      "alias": "high_school_european_history",
      "sample_len": 165,
      "acc,none": 0.36363636363636365,
      "acc_stderr,none": 0.03756335775187897
    },
    "mmlu_high_school_us_history": {
      "name": "mmlu_high_school_us_history",
      "alias": "high_school_us_history",
      "sample_len": 204,
      "acc,none": 0.3480392156862745,
      "acc_stderr,none": 0.03343311240488421
    },
    "mmlu_high_school_world_history": {
      "name": "mmlu_high_school_world_history",
      "alias": "high_school_world_history",
      "sample_len": 237,
      "acc,none": 0.3291139240506329,
      "acc_stderr,none": 0.030587326294702347
    },
    "mmlu_international_law": {
      "name": "mmlu_international_law",
      "alias": "international_law",
      "sample_len": 121,
      "acc,none": 0.256198347107438,
      "acc_stderr,none": 0.03984979653302874
    },
    "mmlu_jurisprudence": {
      "name": "mmlu_jurisprudence",
      "alias": "jurisprudence",
      "sample_len": 108,
      "acc,none": 0.32407407407407407,
      "acc_stderr,none": 0.04524596007030053
    },
    "mmlu_logical_fallacies": {
      "name": "mmlu_logical_fallacies",
      "alias": "logical_fallacies",
      "sample_len": 163,
      "acc,none": 0.2822085889570552,
      "acc_stderr,none": 0.035361178866647414
    },
    "mmlu_moral_disputes": {
      "name": "mmlu_moral_disputes",
      "alias": "moral_disputes",
      "sample_len": 346,
      "acc,none": 0.3265895953757225,
      "acc_stderr,none": 0.02524826477424287
    },
    "mmlu_moral_scenarios": {
      "name": "mmlu_moral_scenarios",
      "alias": "moral_scenarios",
      "sample_len": 895,
      "acc,none": 0.2324022346368715,
      "acc_stderr,none": 0.014125968754673392
    },
    "mmlu_philosophy": {
      "name": "mmlu_philosophy",
      "alias": "philosophy",
      "sample_len": 311,
      "acc,none": 0.2861736334405145,
      "acc_stderr,none": 0.02567025924218898
    },
    "mmlu_prehistory": {
      "name": "mmlu_prehistory",
      "alias": "prehistory",
      "sample_len": 324,
      "acc,none": 0.2932098765432099,
      "acc_stderr,none": 0.02532988817190095
    },
    "mmlu_professional_law": {
      "name": "mmlu_professional_law",
      "alias": "professional_law",
      "sample_len": 1534,
      "acc,none": 0.27509778357235987,
      "acc_stderr,none": 0.011405443620996877
    },
    "mmlu_world_religions": {
      "name": "mmlu_world_religions",
      "alias": "world_religions",
      "sample_len": 171,
      "acc,none": 0.32748538011695905,
      "acc_stderr,none": 0.03599335771456024
    },
    "hellaswag": {
      "name": "hellaswag",
      "alias": "hellaswag",
      "sample_len": 10042,
      "acc,none": 0.33210515833499304,
      "acc_stderr,none": 0.004700059671374276,
      "acc_norm,none": 0.4017128062139016,
      "acc_norm_stderr,none": 0.00489242535637569
    },
    "mmlu_stem": {
      "alias": "stem",
      "name": "mmlu_stem",
      "sample_len": 3153,
      "acc,none": 0.29717729146844274,
      "acc_stderr,none": 0.008137605902798415,
      "sample_count": {
        "acc,none": 3153
      }
    },
    "mmlu_other": {
      "alias": "other",
      "name": "mmlu_other",
      "sample_len": 3107,
      "acc,none": 0.3118764081107177,
      "acc_stderr,none": 0.008305927545512405,
      "sample_count": {
        "acc,none": 3107
      }
    },
    "mmlu_social_sciences": {
      "alias": "social sciences",
      "name": "mmlu_social_sciences",
      "sample_len": 3077,
      "acc,none": 0.32109197270068246,
      "acc_stderr,none": 0.008390948945559081,
      "sample_count": {
        "acc,none": 3077
      }
    },
    "mmlu_humanities": {
      "alias": "humanities",
      "name": "mmlu_humanities",
      "sample_len": 4705,
      "acc,none": 0.28544102019128587,
      "acc_stderr,none": 0.006571933571530638,
      "sample_count": {
        "acc,none": 4705
      }
    },
    "mmlu": {
      "alias": "mmlu",
      "name": "mmlu",
      "sample_len": 14042,
      "acc,none": 0.3017376442102265,
      "acc_stderr,none": 0.0038659889626461315,
      "sample_count": {
        "acc,none": 14042
      }
    }
  },
  "groups": {
    "mmlu_stem": {
      "alias": "stem",
      "name": "mmlu_stem",
      "sample_len": 3153,
      "acc,none": 0.29717729146844274,
      "acc_stderr,none": 0.008137605902798415,
      "sample_count": {
        "acc,none": 3153
      }
    },
    "mmlu_other": {
      "alias": "other",
      "name": "mmlu_other",
      "sample_len": 3107,
      "acc,none": 0.3118764081107177,
      "acc_stderr,none": 0.008305927545512405,
      "sample_count": {
        "acc,none": 3107
      }
    },
    "mmlu_social_sciences": {
      "alias": "social sciences",
      "name": "mmlu_social_sciences",
      "sample_len": 3077,
      "acc,none": 0.32109197270068246,
      "acc_stderr,none": 0.008390948945559081,
      "sample_count": {
        "acc,none": 3077
      }
    },
    "mmlu_humanities": {
      "alias": "humanities",
      "name": "mmlu_humanities",
      "sample_len": 4705,
      "acc,none": 0.28544102019128587,
      "acc_stderr,none": 0.006571933571530638,
      "sample_count": {
        "acc,none": 4705
      }
    },
    "mmlu": {
      "alias": "mmlu",
      "name": "mmlu",
      "sample_len": 14042,
      "acc,none": 0.3017376442102265,
      "acc_stderr,none": 0.0038659889626461315,
      "sample_count": {
        "acc,none": 14042
      }
    }
  },
  "group_subtasks": {
    "mmlu": [
      "mmlu_stem",
      "mmlu_other",
      "mmlu_social_sciences",
      "mmlu_humanities"
    ],
    "mmlu_stem": [
      "mmlu_abstract_algebra",
      "mmlu_anatomy",
      "mmlu_astronomy",
      "mmlu_college_biology",
      "mmlu_college_chemistry",
      "mmlu_college_computer_science",
      "mmlu_college_mathematics",
      "mmlu_college_physics",
      "mmlu_computer_security",
      "mmlu_conceptual_physics",
      "mmlu_electrical_engineering",
      "mmlu_elementary_mathematics",
      "mmlu_high_school_biology",
      "mmlu_high_school_chemistry",
      "mmlu_high_school_computer_science",
      "mmlu_high_school_mathematics",
      "mmlu_high_school_physics",
      "mmlu_high_school_statistics",
      "mmlu_machine_learning"
    ],
    "mmlu_other": [
      "mmlu_business_ethics",
      "mmlu_clinical_knowledge",
      "mmlu_college_medicine",
      "mmlu_global_facts",
      "mmlu_human_aging",
      "mmlu_management",
      "mmlu_marketing",
      "mmlu_medical_genetics",
      "mmlu_miscellaneous",
      "mmlu_nutrition",
      "mmlu_professional_accounting",
      "mmlu_professional_medicine",
      "mmlu_virology"
    ],
    "mmlu_social_sciences": [
      "mmlu_econometrics",
      "mmlu_high_school_geography",
      "mmlu_high_school_government_and_politics",
      "mmlu_high_school_macroeconomics",
      "mmlu_high_school_microeconomics",
      "mmlu_high_school_psychology",
      "mmlu_human_sexuality",
      "mmlu_professional_psychology",
      "mmlu_public_relations",
      "mmlu_security_studies",
      "mmlu_sociology",
      "mmlu_us_foreign_policy"
    ],
    "mmlu_humanities": [
      "mmlu_formal_logic",
      "mmlu_high_school_european_history",
      "mmlu_high_school_us_history",
      "mmlu_high_school_world_history",
      "mmlu_international_law",
      "mmlu_jurisprudence",
      "mmlu_logical_fallacies",
      "mmlu_moral_disputes",
      "mmlu_moral_scenarios",
      "mmlu_philosophy",
      "mmlu_prehistory",
      "mmlu_professional_law",
      "mmlu_world_religions"
    ]
  },
  "configs": {
    "hellaswag": {
      "task": "hellaswag",
      "dataset_path": "Rowan/hellaswag",
      "training_split": "train",
      "validation_split": "validation",
      "process_docs": "def process_docs(dataset: datasets.Dataset) -> datasets.Dataset:\n    def _process_doc(doc):\n        ctx = doc[\"ctx_a\"] + \" \" + doc[\"ctx_b\"].capitalize()\n        out_doc = {\n            \"query\": preprocess(doc[\"activity_label\"] + \": \" + ctx),\n            \"choices\": [preprocess(ending) for ending in doc[\"endings\"]],\n            \"gold\": int(doc[\"label\"]),\n        }\n        return out_doc\n\n    return dataset.map(_process_doc)\n",
      "doc_to_text": "{{query}}",
      "doc_to_target": "{{label}}",
      "unsafe_code": false,
      "doc_to_choice": "choices",
      "description": "",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "default",
        "split": null,
        "process_docs": "<function process_docs at 0x76a6041f80e0>",
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{query}}",
        "doc_to_choice": "choices",
        "doc_to_target": "{{label}}",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        },
        {
          "metric": "acc_norm",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/hellaswag/hellaswag.yaml"
      }
    },
    "mmlu_abstract_algebra": {
      "task": "mmlu_abstract_algebra",
      "task_alias": "abstract_algebra",
      "dataset_path": "cais/mmlu",
      "dataset_name": "abstract_algebra",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about abstract algebra.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_abstract_algebra.yaml"
      }
    },
    "mmlu_anatomy": {
      "task": "mmlu_anatomy",
      "task_alias": "anatomy",
      "dataset_path": "cais/mmlu",
      "dataset_name": "anatomy",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about anatomy.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_anatomy.yaml"
      }
    },
    "mmlu_astronomy": {
      "task": "mmlu_astronomy",
      "task_alias": "astronomy",
      "dataset_path": "cais/mmlu",
      "dataset_name": "astronomy",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about astronomy.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_astronomy.yaml"
      }
    },
    "mmlu_business_ethics": {
      "task": "mmlu_business_ethics",
      "task_alias": "business_ethics",
      "dataset_path": "cais/mmlu",
      "dataset_name": "business_ethics",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about business ethics.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_business_ethics.yaml"
      }
    },
    "mmlu_clinical_knowledge": {
      "task": "mmlu_clinical_knowledge",
      "task_alias": "clinical_knowledge",
      "dataset_path": "cais/mmlu",
      "dataset_name": "clinical_knowledge",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about clinical knowledge.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_clinical_knowledge.yaml"
      }
    },
    "mmlu_college_biology": {
      "task": "mmlu_college_biology",
      "task_alias": "college_biology",
      "dataset_path": "cais/mmlu",
      "dataset_name": "college_biology",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about college biology.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_college_biology.yaml"
      }
    },
    "mmlu_college_chemistry": {
      "task": "mmlu_college_chemistry",
      "task_alias": "college_chemistry",
      "dataset_path": "cais/mmlu",
      "dataset_name": "college_chemistry",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about college chemistry.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_college_chemistry.yaml"
      }
    },
    "mmlu_college_computer_science": {
      "task": "mmlu_college_computer_science",
      "task_alias": "college_computer_science",
      "dataset_path": "cais/mmlu",
      "dataset_name": "college_computer_science",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about college computer science.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_college_computer_science.yaml"
      }
    },
    "mmlu_college_mathematics": {
      "task": "mmlu_college_mathematics",
      "task_alias": "college_mathematics",
      "dataset_path": "cais/mmlu",
      "dataset_name": "college_mathematics",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about college mathematics.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_college_mathematics.yaml"
      }
    },
    "mmlu_college_medicine": {
      "task": "mmlu_college_medicine",
      "task_alias": "college_medicine",
      "dataset_path": "cais/mmlu",
      "dataset_name": "college_medicine",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about college medicine.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_college_medicine.yaml"
      }
    },
    "mmlu_college_physics": {
      "task": "mmlu_college_physics",
      "task_alias": "college_physics",
      "dataset_path": "cais/mmlu",
      "dataset_name": "college_physics",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about college physics.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_college_physics.yaml"
      }
    },
    "mmlu_computer_security": {
      "task": "mmlu_computer_security",
      "task_alias": "computer_security",
      "dataset_path": "cais/mmlu",
      "dataset_name": "computer_security",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about computer security.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_computer_security.yaml"
      }
    },
    "mmlu_conceptual_physics": {
      "task": "mmlu_conceptual_physics",
      "task_alias": "conceptual_physics",
      "dataset_path": "cais/mmlu",
      "dataset_name": "conceptual_physics",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about conceptual physics.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_conceptual_physics.yaml"
      }
    },
    "mmlu_econometrics": {
      "task": "mmlu_econometrics",
      "task_alias": "econometrics",
      "dataset_path": "cais/mmlu",
      "dataset_name": "econometrics",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about econometrics.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_econometrics.yaml"
      }
    },
    "mmlu_electrical_engineering": {
      "task": "mmlu_electrical_engineering",
      "task_alias": "electrical_engineering",
      "dataset_path": "cais/mmlu",
      "dataset_name": "electrical_engineering",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about electrical engineering.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_electrical_engineering.yaml"
      }
    },
    "mmlu_elementary_mathematics": {
      "task": "mmlu_elementary_mathematics",
      "task_alias": "elementary_mathematics",
      "dataset_path": "cais/mmlu",
      "dataset_name": "elementary_mathematics",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about elementary mathematics.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_elementary_mathematics.yaml"
      }
    },
    "mmlu_formal_logic": {
      "task": "mmlu_formal_logic",
      "task_alias": "formal_logic",
      "dataset_path": "cais/mmlu",
      "dataset_name": "formal_logic",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about formal logic.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_formal_logic.yaml"
      }
    },
    "mmlu_global_facts": {
      "task": "mmlu_global_facts",
      "task_alias": "global_facts",
      "dataset_path": "cais/mmlu",
      "dataset_name": "global_facts",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about global facts.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_global_facts.yaml"
      }
    },
    "mmlu_high_school_biology": {
      "task": "mmlu_high_school_biology",
      "task_alias": "high_school_biology",
      "dataset_path": "cais/mmlu",
      "dataset_name": "high_school_biology",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about high school biology.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_high_school_biology.yaml"
      }
    },
    "mmlu_high_school_chemistry": {
      "task": "mmlu_high_school_chemistry",
      "task_alias": "high_school_chemistry",
      "dataset_path": "cais/mmlu",
      "dataset_name": "high_school_chemistry",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about high school chemistry.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_high_school_chemistry.yaml"
      }
    },
    "mmlu_high_school_computer_science": {
      "task": "mmlu_high_school_computer_science",
      "task_alias": "high_school_computer_science",
      "dataset_path": "cais/mmlu",
      "dataset_name": "high_school_computer_science",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about high school computer science.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_high_school_computer_science.yaml"
      }
    },
    "mmlu_high_school_european_history": {
      "task": "mmlu_high_school_european_history",
      "task_alias": "high_school_european_history",
      "dataset_path": "cais/mmlu",
      "dataset_name": "high_school_european_history",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about high school european history.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_high_school_european_history.yaml"
      }
    },
    "mmlu_high_school_geography": {
      "task": "mmlu_high_school_geography",
      "task_alias": "high_school_geography",
      "dataset_path": "cais/mmlu",
      "dataset_name": "high_school_geography",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about high school geography.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_high_school_geography.yaml"
      }
    },
    "mmlu_high_school_government_and_politics": {
      "task": "mmlu_high_school_government_and_politics",
      "task_alias": "high_school_government_and_politics",
      "dataset_path": "cais/mmlu",
      "dataset_name": "high_school_government_and_politics",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about high school government and politics.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_high_school_government_and_politics.yaml"
      }
    },
    "mmlu_high_school_macroeconomics": {
      "task": "mmlu_high_school_macroeconomics",
      "task_alias": "high_school_macroeconomics",
      "dataset_path": "cais/mmlu",
      "dataset_name": "high_school_macroeconomics",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about high school macroeconomics.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_high_school_macroeconomics.yaml"
      }
    },
    "mmlu_high_school_mathematics": {
      "task": "mmlu_high_school_mathematics",
      "task_alias": "high_school_mathematics",
      "dataset_path": "cais/mmlu",
      "dataset_name": "high_school_mathematics",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about high school mathematics.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_high_school_mathematics.yaml"
      }
    },
    "mmlu_high_school_microeconomics": {
      "task": "mmlu_high_school_microeconomics",
      "task_alias": "high_school_microeconomics",
      "dataset_path": "cais/mmlu",
      "dataset_name": "high_school_microeconomics",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about high school microeconomics.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_high_school_microeconomics.yaml"
      }
    },
    "mmlu_high_school_physics": {
      "task": "mmlu_high_school_physics",
      "task_alias": "high_school_physics",
      "dataset_path": "cais/mmlu",
      "dataset_name": "high_school_physics",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about high school physics.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_high_school_physics.yaml"
      }
    },
    "mmlu_high_school_psychology": {
      "task": "mmlu_high_school_psychology",
      "task_alias": "high_school_psychology",
      "dataset_path": "cais/mmlu",
      "dataset_name": "high_school_psychology",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about high school psychology.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_high_school_psychology.yaml"
      }
    },
    "mmlu_high_school_statistics": {
      "task": "mmlu_high_school_statistics",
      "task_alias": "high_school_statistics",
      "dataset_path": "cais/mmlu",
      "dataset_name": "high_school_statistics",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about high school statistics.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_high_school_statistics.yaml"
      }
    },
    "mmlu_high_school_us_history": {
      "task": "mmlu_high_school_us_history",
      "task_alias": "high_school_us_history",
      "dataset_path": "cais/mmlu",
      "dataset_name": "high_school_us_history",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about high school us history.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_high_school_us_history.yaml"
      }
    },
    "mmlu_high_school_world_history": {
      "task": "mmlu_high_school_world_history",
      "task_alias": "high_school_world_history",
      "dataset_path": "cais/mmlu",
      "dataset_name": "high_school_world_history",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about high school world history.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_high_school_world_history.yaml"
      }
    },
    "mmlu_human_aging": {
      "task": "mmlu_human_aging",
      "task_alias": "human_aging",
      "dataset_path": "cais/mmlu",
      "dataset_name": "human_aging",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about human aging.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_human_aging.yaml"
      }
    },
    "mmlu_human_sexuality": {
      "task": "mmlu_human_sexuality",
      "task_alias": "human_sexuality",
      "dataset_path": "cais/mmlu",
      "dataset_name": "human_sexuality",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about human sexuality.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_human_sexuality.yaml"
      }
    },
    "mmlu_international_law": {
      "task": "mmlu_international_law",
      "task_alias": "international_law",
      "dataset_path": "cais/mmlu",
      "dataset_name": "international_law",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about international law.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_international_law.yaml"
      }
    },
    "mmlu_jurisprudence": {
      "task": "mmlu_jurisprudence",
      "task_alias": "jurisprudence",
      "dataset_path": "cais/mmlu",
      "dataset_name": "jurisprudence",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about jurisprudence.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_jurisprudence.yaml"
      }
    },
    "mmlu_logical_fallacies": {
      "task": "mmlu_logical_fallacies",
      "task_alias": "logical_fallacies",
      "dataset_path": "cais/mmlu",
      "dataset_name": "logical_fallacies",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about logical fallacies.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_logical_fallacies.yaml"
      }
    },
    "mmlu_machine_learning": {
      "task": "mmlu_machine_learning",
      "task_alias": "machine_learning",
      "dataset_path": "cais/mmlu",
      "dataset_name": "machine_learning",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about machine learning.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_machine_learning.yaml"
      }
    },
    "mmlu_management": {
      "task": "mmlu_management",
      "task_alias": "management",
      "dataset_path": "cais/mmlu",
      "dataset_name": "management",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about management.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_management.yaml"
      }
    },
    "mmlu_marketing": {
      "task": "mmlu_marketing",
      "task_alias": "marketing",
      "dataset_path": "cais/mmlu",
      "dataset_name": "marketing",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about marketing.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_marketing.yaml"
      }
    },
    "mmlu_medical_genetics": {
      "task": "mmlu_medical_genetics",
      "task_alias": "medical_genetics",
      "dataset_path": "cais/mmlu",
      "dataset_name": "medical_genetics",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about medical genetics.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_medical_genetics.yaml"
      }
    },
    "mmlu_miscellaneous": {
      "task": "mmlu_miscellaneous",
      "task_alias": "miscellaneous",
      "dataset_path": "cais/mmlu",
      "dataset_name": "miscellaneous",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about miscellaneous.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_miscellaneous.yaml"
      }
    },
    "mmlu_moral_disputes": {
      "task": "mmlu_moral_disputes",
      "task_alias": "moral_disputes",
      "dataset_path": "cais/mmlu",
      "dataset_name": "moral_disputes",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about moral disputes.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_moral_disputes.yaml"
      }
    },
    "mmlu_moral_scenarios": {
      "task": "mmlu_moral_scenarios",
      "task_alias": "moral_scenarios",
      "dataset_path": "cais/mmlu",
      "dataset_name": "moral_scenarios",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about moral scenarios.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_moral_scenarios.yaml"
      }
    },
    "mmlu_nutrition": {
      "task": "mmlu_nutrition",
      "task_alias": "nutrition",
      "dataset_path": "cais/mmlu",
      "dataset_name": "nutrition",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about nutrition.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_nutrition.yaml"
      }
    },
    "mmlu_philosophy": {
      "task": "mmlu_philosophy",
      "task_alias": "philosophy",
      "dataset_path": "cais/mmlu",
      "dataset_name": "philosophy",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about philosophy.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_philosophy.yaml"
      }
    },
    "mmlu_prehistory": {
      "task": "mmlu_prehistory",
      "task_alias": "prehistory",
      "dataset_path": "cais/mmlu",
      "dataset_name": "prehistory",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about prehistory.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_prehistory.yaml"
      }
    },
    "mmlu_professional_accounting": {
      "task": "mmlu_professional_accounting",
      "task_alias": "professional_accounting",
      "dataset_path": "cais/mmlu",
      "dataset_name": "professional_accounting",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about professional accounting.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_professional_accounting.yaml"
      }
    },
    "mmlu_professional_law": {
      "task": "mmlu_professional_law",
      "task_alias": "professional_law",
      "dataset_path": "cais/mmlu",
      "dataset_name": "professional_law",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about professional law.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_professional_law.yaml"
      }
    },
    "mmlu_professional_medicine": {
      "task": "mmlu_professional_medicine",
      "task_alias": "professional_medicine",
      "dataset_path": "cais/mmlu",
      "dataset_name": "professional_medicine",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about professional medicine.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_professional_medicine.yaml"
      }
    },
    "mmlu_professional_psychology": {
      "task": "mmlu_professional_psychology",
      "task_alias": "professional_psychology",
      "dataset_path": "cais/mmlu",
      "dataset_name": "professional_psychology",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about professional psychology.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_professional_psychology.yaml"
      }
    },
    "mmlu_public_relations": {
      "task": "mmlu_public_relations",
      "task_alias": "public_relations",
      "dataset_path": "cais/mmlu",
      "dataset_name": "public_relations",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about public relations.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_public_relations.yaml"
      }
    },
    "mmlu_security_studies": {
      "task": "mmlu_security_studies",
      "task_alias": "security_studies",
      "dataset_path": "cais/mmlu",
      "dataset_name": "security_studies",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about security studies.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_security_studies.yaml"
      }
    },
    "mmlu_sociology": {
      "task": "mmlu_sociology",
      "task_alias": "sociology",
      "dataset_path": "cais/mmlu",
      "dataset_name": "sociology",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about sociology.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_sociology.yaml"
      }
    },
    "mmlu_us_foreign_policy": {
      "task": "mmlu_us_foreign_policy",
      "task_alias": "us_foreign_policy",
      "dataset_path": "cais/mmlu",
      "dataset_name": "us_foreign_policy",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about us foreign policy.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_us_foreign_policy.yaml"
      }
    },
    "mmlu_virology": {
      "task": "mmlu_virology",
      "task_alias": "virology",
      "dataset_path": "cais/mmlu",
      "dataset_name": "virology",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about virology.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_virology.yaml"
      }
    },
    "mmlu_world_religions": {
      "task": "mmlu_world_religions",
      "task_alias": "world_religions",
      "dataset_path": "cais/mmlu",
      "dataset_name": "world_religions",
      "test_split": "test",
      "fewshot_split": "dev",
      "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
      "doc_to_target": "answer",
      "unsafe_code": false,
      "doc_to_choice": [
        "A",
        "B",
        "C",
        "D"
      ],
      "description": "The following are multiple choice questions (with answers) about world religions.\n\n",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "first_n",
        "split": "dev",
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "{{question.strip()}}\nA. {{choices[0]}}\nB. {{choices[1]}}\nC. {{choices[2]}}\nD. {{choices[3]}}\nAnswer:",
        "doc_to_choice": [
          "A",
          "B",
          "C",
          "D"
        ],
        "doc_to_target": "answer",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": false,
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/mmlu/default/mmlu_world_religions.yaml"
      }
    },
    "piqa": {
      "task": "piqa",
      "dataset_path": "baber/piqa",
      "training_split": "train",
      "validation_split": "validation",
      "doc_to_text": "Question: {{goal}}\nAnswer:",
      "doc_to_target": "label",
      "unsafe_code": false,
      "doc_to_choice": "{{[sol1, sol2]}}",
      "description": "",
      "target_delimiter": " ",
      "fewshot_delimiter": "\n\n",
      "fewshot_config": {
        "sampler": "default",
        "split": null,
        "process_docs": null,
        "fewshot_indices": null,
        "samples": null,
        "doc_to_text": "Question: {{goal}}\nAnswer:",
        "doc_to_choice": "{{[sol1, sol2]}}",
        "doc_to_target": "label",
        "gen_prefix": null,
        "fewshot_delimiter": "\n\n",
        "target_delimiter": " "
      },
      "num_fewshot": 0,
      "metric_list": [
        {
          "metric": "acc",
          "aggregation": "mean",
          "higher_is_better": true
        },
        {
          "metric": "acc_norm",
          "aggregation": "mean",
          "higher_is_better": true
        }
      ],
      "output_type": "multiple_choice",
      "repeats": 1,
      "should_decontaminate": true,
      "doc_to_decontamination_query": "goal",
      "metadata": {
        "version": 1.0,
        "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
        "dtype": "bfloat16",
        "device_map": "auto",
        "trust_remote_code": true,
        "config_source": "/root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/venv/lib/python3.12/site-packages/lm_eval/tasks/piqa/piqa.yaml"
      }
    }
  },
  "versions": {
    "hellaswag": 1.0,
    "mmlu": "2",
    "mmlu_abstract_algebra": 1.0,
    "mmlu_anatomy": 1.0,
    "mmlu_astronomy": 1.0,
    "mmlu_business_ethics": 1.0,
    "mmlu_clinical_knowledge": 1.0,
    "mmlu_college_biology": 1.0,
    "mmlu_college_chemistry": 1.0,
    "mmlu_college_computer_science": 1.0,
    "mmlu_college_mathematics": 1.0,
    "mmlu_college_medicine": 1.0,
    "mmlu_college_physics": 1.0,
    "mmlu_computer_security": 1.0,
    "mmlu_conceptual_physics": 1.0,
    "mmlu_econometrics": 1.0,
    "mmlu_electrical_engineering": 1.0,
    "mmlu_elementary_mathematics": 1.0,
    "mmlu_formal_logic": 1.0,
    "mmlu_global_facts": 1.0,
    "mmlu_high_school_biology": 1.0,
    "mmlu_high_school_chemistry": 1.0,
    "mmlu_high_school_computer_science": 1.0,
    "mmlu_high_school_european_history": 1.0,
    "mmlu_high_school_geography": 1.0,
    "mmlu_high_school_government_and_politics": 1.0,
    "mmlu_high_school_macroeconomics": 1.0,
    "mmlu_high_school_mathematics": 1.0,
    "mmlu_high_school_microeconomics": 1.0,
    "mmlu_high_school_physics": 1.0,
    "mmlu_high_school_psychology": 1.0,
    "mmlu_high_school_statistics": 1.0,
    "mmlu_high_school_us_history": 1.0,
    "mmlu_high_school_world_history": 1.0,
    "mmlu_human_aging": 1.0,
    "mmlu_human_sexuality": 1.0,
    "mmlu_humanities": "2",
    "mmlu_international_law": 1.0,
    "mmlu_jurisprudence": 1.0,
    "mmlu_logical_fallacies": 1.0,
    "mmlu_machine_learning": 1.0,
    "mmlu_management": 1.0,
    "mmlu_marketing": 1.0,
    "mmlu_medical_genetics": 1.0,
    "mmlu_miscellaneous": 1.0,
    "mmlu_moral_disputes": 1.0,
    "mmlu_moral_scenarios": 1.0,
    "mmlu_nutrition": 1.0,
    "mmlu_other": "2",
    "mmlu_philosophy": 1.0,
    "mmlu_prehistory": 1.0,
    "mmlu_professional_accounting": 1.0,
    "mmlu_professional_law": 1.0,
    "mmlu_professional_medicine": 1.0,
    "mmlu_professional_psychology": 1.0,
    "mmlu_public_relations": 1.0,
    "mmlu_security_studies": 1.0,
    "mmlu_social_sciences": "2",
    "mmlu_sociology": 1.0,
    "mmlu_stem": "2",
    "mmlu_us_foreign_policy": 1.0,
    "mmlu_virology": 1.0,
    "mmlu_world_religions": 1.0,
    "piqa": 1.0
  },
  "n-shot": {
    "hellaswag": 0,
    "mmlu_abstract_algebra": 0,
    "mmlu_anatomy": 0,
    "mmlu_astronomy": 0,
    "mmlu_business_ethics": 0,
    "mmlu_clinical_knowledge": 0,
    "mmlu_college_biology": 0,
    "mmlu_college_chemistry": 0,
    "mmlu_college_computer_science": 0,
    "mmlu_college_mathematics": 0,
    "mmlu_college_medicine": 0,
    "mmlu_college_physics": 0,
    "mmlu_computer_security": 0,
    "mmlu_conceptual_physics": 0,
    "mmlu_econometrics": 0,
    "mmlu_electrical_engineering": 0,
    "mmlu_elementary_mathematics": 0,
    "mmlu_formal_logic": 0,
    "mmlu_global_facts": 0,
    "mmlu_high_school_biology": 0,
    "mmlu_high_school_chemistry": 0,
    "mmlu_high_school_computer_science": 0,
    "mmlu_high_school_european_history": 0,
    "mmlu_high_school_geography": 0,
    "mmlu_high_school_government_and_politics": 0,
    "mmlu_high_school_macroeconomics": 0,
    "mmlu_high_school_mathematics": 0,
    "mmlu_high_school_microeconomics": 0,
    "mmlu_high_school_physics": 0,
    "mmlu_high_school_psychology": 0,
    "mmlu_high_school_statistics": 0,
    "mmlu_high_school_us_history": 0,
    "mmlu_high_school_world_history": 0,
    "mmlu_human_aging": 0,
    "mmlu_human_sexuality": 0,
    "mmlu_humanities": 0,
    "mmlu_international_law": 0,
    "mmlu_jurisprudence": 0,
    "mmlu_logical_fallacies": 0,
    "mmlu_machine_learning": 0,
    "mmlu_management": 0,
    "mmlu_marketing": 0,
    "mmlu_medical_genetics": 0,
    "mmlu_miscellaneous": 0,
    "mmlu_moral_disputes": 0,
    "mmlu_moral_scenarios": 0,
    "mmlu_nutrition": 0,
    "mmlu_other": 0,
    "mmlu_philosophy": 0,
    "mmlu_prehistory": 0,
    "mmlu_professional_accounting": 0,
    "mmlu_professional_law": 0,
    "mmlu_professional_medicine": 0,
    "mmlu_professional_psychology": 0,
    "mmlu_public_relations": 0,
    "mmlu_security_studies": 0,
    "mmlu_social_sciences": 0,
    "mmlu_sociology": 0,
    "mmlu_stem": 0,
    "mmlu_us_foreign_policy": 0,
    "mmlu_virology": 0,
    "mmlu_world_religions": 0,
    "piqa": 0
  },
  "higher_is_better": {
    "hellaswag": {
      "acc": true,
      "acc_norm": true
    },
    "mmlu_abstract_algebra": {
      "acc": true
    },
    "mmlu_anatomy": {
      "acc": true
    },
    "mmlu_astronomy": {
      "acc": true
    },
    "mmlu_business_ethics": {
      "acc": true
    },
    "mmlu_clinical_knowledge": {
      "acc": true
    },
    "mmlu_college_biology": {
      "acc": true
    },
    "mmlu_college_chemistry": {
      "acc": true
    },
    "mmlu_college_computer_science": {
      "acc": true
    },
    "mmlu_college_mathematics": {
      "acc": true
    },
    "mmlu_college_medicine": {
      "acc": true
    },
    "mmlu_college_physics": {
      "acc": true
    },
    "mmlu_computer_security": {
      "acc": true
    },
    "mmlu_conceptual_physics": {
      "acc": true
    },
    "mmlu_econometrics": {
      "acc": true
    },
    "mmlu_electrical_engineering": {
      "acc": true
    },
    "mmlu_elementary_mathematics": {
      "acc": true
    },
    "mmlu_formal_logic": {
      "acc": true
    },
    "mmlu_global_facts": {
      "acc": true
    },
    "mmlu_high_school_biology": {
      "acc": true
    },
    "mmlu_high_school_chemistry": {
      "acc": true
    },
    "mmlu_high_school_computer_science": {
      "acc": true
    },
    "mmlu_high_school_european_history": {
      "acc": true
    },
    "mmlu_high_school_geography": {
      "acc": true
    },
    "mmlu_high_school_government_and_politics": {
      "acc": true
    },
    "mmlu_high_school_macroeconomics": {
      "acc": true
    },
    "mmlu_high_school_mathematics": {
      "acc": true
    },
    "mmlu_high_school_microeconomics": {
      "acc": true
    },
    "mmlu_high_school_physics": {
      "acc": true
    },
    "mmlu_high_school_psychology": {
      "acc": true
    },
    "mmlu_high_school_statistics": {
      "acc": true
    },
    "mmlu_high_school_us_history": {
      "acc": true
    },
    "mmlu_high_school_world_history": {
      "acc": true
    },
    "mmlu_human_aging": {
      "acc": true
    },
    "mmlu_human_sexuality": {
      "acc": true
    },
    "mmlu_humanities": {
      "acc": true
    },
    "mmlu_international_law": {
      "acc": true
    },
    "mmlu_jurisprudence": {
      "acc": true
    },
    "mmlu_logical_fallacies": {
      "acc": true
    },
    "mmlu_machine_learning": {
      "acc": true
    },
    "mmlu_management": {
      "acc": true
    },
    "mmlu_marketing": {
      "acc": true
    },
    "mmlu_medical_genetics": {
      "acc": true
    },
    "mmlu_miscellaneous": {
      "acc": true
    },
    "mmlu_moral_disputes": {
      "acc": true
    },
    "mmlu_moral_scenarios": {
      "acc": true
    },
    "mmlu_nutrition": {
      "acc": true
    },
    "mmlu_other": {
      "acc": true
    },
    "mmlu_philosophy": {
      "acc": true
    },
    "mmlu_prehistory": {
      "acc": true
    },
    "mmlu_professional_accounting": {
      "acc": true
    },
    "mmlu_professional_law": {
      "acc": true
    },
    "mmlu_professional_medicine": {
      "acc": true
    },
    "mmlu_professional_psychology": {
      "acc": true
    },
    "mmlu_public_relations": {
      "acc": true
    },
    "mmlu_security_studies": {
      "acc": true
    },
    "mmlu_social_sciences": {
      "acc": true
    },
    "mmlu_sociology": {
      "acc": true
    },
    "mmlu_stem": {
      "acc": true
    },
    "mmlu_us_foreign_policy": {
      "acc": true
    },
    "mmlu_virology": {
      "acc": true
    },
    "mmlu_world_religions": {
      "acc": true
    },
    "piqa": {
      "acc": true,
      "acc_norm": true
    }
  },
  "n-samples": {
    "piqa": {
      "original": 1838,
      "effective": 1838
    },
    "mmlu_abstract_algebra": {
      "original": 100,
      "effective": 100
    },
    "mmlu_anatomy": {
      "original": 135,
      "effective": 135
    },
    "mmlu_astronomy": {
      "original": 152,
      "effective": 152
    },
    "mmlu_college_biology": {
      "original": 144,
      "effective": 144
    },
    "mmlu_college_chemistry": {
      "original": 100,
      "effective": 100
    },
    "mmlu_college_computer_science": {
      "original": 100,
      "effective": 100
    },
    "mmlu_college_mathematics": {
      "original": 100,
      "effective": 100
    },
    "mmlu_college_physics": {
      "original": 102,
      "effective": 102
    },
    "mmlu_computer_security": {
      "original": 100,
      "effective": 100
    },
    "mmlu_conceptual_physics": {
      "original": 235,
      "effective": 235
    },
    "mmlu_electrical_engineering": {
      "original": 145,
      "effective": 145
    },
    "mmlu_elementary_mathematics": {
      "original": 378,
      "effective": 378
    },
    "mmlu_high_school_biology": {
      "original": 310,
      "effective": 310
    },
    "mmlu_high_school_chemistry": {
      "original": 203,
      "effective": 203
    },
    "mmlu_high_school_computer_science": {
      "original": 100,
      "effective": 100
    },
    "mmlu_high_school_mathematics": {
      "original": 270,
      "effective": 270
    },
    "mmlu_high_school_physics": {
      "original": 151,
      "effective": 151
    },
    "mmlu_high_school_statistics": {
      "original": 216,
      "effective": 216
    },
    "mmlu_machine_learning": {
      "original": 112,
      "effective": 112
    },
    "mmlu_business_ethics": {
      "original": 100,
      "effective": 100
    },
    "mmlu_clinical_knowledge": {
      "original": 265,
      "effective": 265
    },
    "mmlu_college_medicine": {
      "original": 173,
      "effective": 173
    },
    "mmlu_global_facts": {
      "original": 100,
      "effective": 100
    },
    "mmlu_human_aging": {
      "original": 223,
      "effective": 223
    },
    "mmlu_management": {
      "original": 103,
      "effective": 103
    },
    "mmlu_marketing": {
      "original": 234,
      "effective": 234
    },
    "mmlu_medical_genetics": {
      "original": 100,
      "effective": 100
    },
    "mmlu_miscellaneous": {
      "original": 783,
      "effective": 783
    },
    "mmlu_nutrition": {
      "original": 306,
      "effective": 306
    },
    "mmlu_professional_accounting": {
      "original": 282,
      "effective": 282
    },
    "mmlu_professional_medicine": {
      "original": 272,
      "effective": 272
    },
    "mmlu_virology": {
      "original": 166,
      "effective": 166
    },
    "mmlu_econometrics": {
      "original": 114,
      "effective": 114
    },
    "mmlu_high_school_geography": {
      "original": 198,
      "effective": 198
    },
    "mmlu_high_school_government_and_politics": {
      "original": 193,
      "effective": 193
    },
    "mmlu_high_school_macroeconomics": {
      "original": 390,
      "effective": 390
    },
    "mmlu_high_school_microeconomics": {
      "original": 238,
      "effective": 238
    },
    "mmlu_high_school_psychology": {
      "original": 545,
      "effective": 545
    },
    "mmlu_human_sexuality": {
      "original": 131,
      "effective": 131
    },
    "mmlu_professional_psychology": {
      "original": 612,
      "effective": 612
    },
    "mmlu_public_relations": {
      "original": 110,
      "effective": 110
    },
    "mmlu_security_studies": {
      "original": 245,
      "effective": 245
    },
    "mmlu_sociology": {
      "original": 201,
      "effective": 201
    },
    "mmlu_us_foreign_policy": {
      "original": 100,
      "effective": 100
    },
    "mmlu_formal_logic": {
      "original": 126,
      "effective": 126
    },
    "mmlu_high_school_european_history": {
      "original": 165,
      "effective": 165
    },
    "mmlu_high_school_us_history": {
      "original": 204,
      "effective": 204
    },
    "mmlu_high_school_world_history": {
      "original": 237,
      "effective": 237
    },
    "mmlu_international_law": {
      "original": 121,
      "effective": 121
    },
    "mmlu_jurisprudence": {
      "original": 108,
      "effective": 108
    },
    "mmlu_logical_fallacies": {
      "original": 163,
      "effective": 163
    },
    "mmlu_moral_disputes": {
      "original": 346,
      "effective": 346
    },
    "mmlu_moral_scenarios": {
      "original": 895,
      "effective": 895
    },
    "mmlu_philosophy": {
      "original": 311,
      "effective": 311
    },
    "mmlu_prehistory": {
      "original": 324,
      "effective": 324
    },
    "mmlu_professional_law": {
      "original": 1534,
      "effective": 1534
    },
    "mmlu_world_religions": {
      "original": 171,
      "effective": 171
    },
    "hellaswag": {
      "original": 10042,
      "effective": 10042
    }
  },
  "config": {
    "model": "hf",
    "model_args": {
      "pretrained": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
      "dtype": "bfloat16",
      "device_map": "auto",
      "trust_remote_code": true
    },
    "model_num_parameters": 136206208,
    "model_dtype": "torch.bfloat16",
    "model_revision": "main",
    "model_sha": "",
    "batch_size": "8",
    "batch_sizes": [],
    "device": "cuda",
    "use_cache": null,
    "limit": null,
    "bootstrap_iters": 100000,
    "gen_kwargs": {
      "max_gen_toks": 2048
    },
    "random_seed": 0,
    "numpy_seed": 1234,
    "torch_seed": 1234,
    "fewshot_seed": 1234
  },
  "git_hash": null,
  "date": 1779247727.392387,
  "pretty_env_info": "PyTorch version: 2.6.0+cu124\nIs debug build: False\nCUDA used to build PyTorch: 12.4\nROCM used to build PyTorch: N/A\n\nOS: Ubuntu 24.04.4 LTS (x86_64)\nGCC version: (Ubuntu 13.3.0-6ubuntu2~24.04.1) 13.3.0\nClang version: Could not collect\nCMake version: Could not collect\nLibc version: glibc-2.39\n\nPython version: 3.12.13 (main, Apr 14 2026, 14:29:00) [Clang 22.1.3 ] (64-bit runtime)\nPython platform: Linux-6.8.0-60-generic-x86_64-with-glibc2.39\nIs CUDA available: True\nCUDA runtime version: 12.0.140\nCUDA_MODULE_LOADING set to: LAZY\nGPU models and configuration: GPU 0: NVIDIA GeForce RTX 4090\nNvidia driver version: 550.127.05\ncuDNN version: Could not collect\nHIP runtime version: N/A\nMIOpen runtime version: N/A\nIs XNNPACK available: True\n\nCPU:\nArchitecture:                         x86_64\nCPU op-mode(s):                       32-bit, 64-bit\nAddress sizes:                        48 bits physical, 48 bits virtual\nByte Order:                           Little Endian\nCPU(s):                               128\nOn-line CPU(s) list:                  0-127\nVendor ID:                            AuthenticAMD\nModel name:                           AMD EPYC 75F3 32-Core Processor\nCPU family:                           25\nModel:                                1\nThread(s) per core:                   2\nCore(s) per socket:                   32\nSocket(s):                            2\nStepping:                             1\nFrequency boost:                      enabled\nCPU(s) scaling MHz:                   50%\nCPU max MHz:                          4041.8450\nCPU min MHz:                          1500.0000\nBogoMIPS:                             5900.51\nFlags:                                fpu vme de pse tsc msr pae mce cx8 apic sep mtrr pge mca cmov pat pse36 clflush mmx fxsr sse sse2 ht syscall nx mmxext fxsr_opt pdpe1gb rdtscp lm constant_tsc rep_good nopl nonstop_tsc cpuid extd_apicid aperfmperf rapl pni pclmulqdq monitor ssse3 fma cx16 pcid sse4_1 sse4_2 movbe popcnt aes xsave avx f16c rdrand lahf_lm cmp_legacy svm extapic cr8_legacy abm sse4a misalignsse 3dnowprefetch osvw ibs skinit wdt tce topoext perfctr_core perfctr_nb bpext perfctr_llc mwaitx cpb cat_l3 cdp_l3 hw_pstate ssbd mba ibrs ibpb stibp vmmcall fsgsbase bmi1 avx2 smep bmi2 invpcid cqm rdt_a rdseed adx smap clflushopt clwb sha_ni xsaveopt xsavec xgetbv1 xsaves cqm_llc cqm_occup_llc cqm_mbm_total cqm_mbm_local user_shstk clzero irperf xsaveerptr rdpru wbnoinvd amd_ppin brs arat npt lbrv svm_lock nrip_save tsc_scale vmcb_clean flushbyasid decodeassists pausefilter pfthreshold v_vmsave_vmload vgif v_spec_ctrl umip pku ospke vaes vpclmulqdq rdpid overflow_recov succor smca debug_swap\nVirtualization:                       AMD-V\nL1d cache:                            2 MiB (64 instances)\nL1i cache:                            2 MiB (64 instances)\nL2 cache:                             32 MiB (64 instances)\nL3 cache:                             512 MiB (16 instances)\nNUMA node(s):                         2\nNUMA node0 CPU(s):                    0-31,64-95\nNUMA node1 CPU(s):                    32-63,96-127\nVulnerability Gather data sampling:   Not affected\nVulnerability Itlb multihit:          Not affected\nVulnerability L1tf:                   Not affected\nVulnerability Mds:                    Not affected\nVulnerability Meltdown:               Not affected\nVulnerability Mmio stale data:        Not affected\nVulnerability Reg file data sampling: Not affected\nVulnerability Retbleed:               Not affected\nVulnerability Spec rstack overflow:   Mitigation; Safe RET\nVulnerability Spec store bypass:      Mitigation; Speculative Store Bypass disabled via prctl\nVulnerability Spectre v1:             Mitigation; usercopy/swapgs barriers and __user pointer sanitization\nVulnerability Spectre v2:             Mitigation; Retpolines; IBPB conditional; IBRS_FW; STIBP always-on; RSB filling; PBRSB-eIBRS Not affected; BHI Not affected\nVulnerability Srbds:                  Not affected\nVulnerability Tsx async abort:        Not affected\n\nVersions of relevant libraries:\n[pip3] numpy==2.4.6\n[pip3] nvidia-cublas-cu12==12.4.5.8\n[pip3] nvidia-cuda-cupti-cu12==12.4.127\n[pip3] nvidia-cuda-nvrtc-cu12==12.4.127\n[pip3] nvidia-cuda-runtime-cu12==12.4.127\n[pip3] nvidia-cudnn-cu12==9.1.0.70\n[pip3] nvidia-cufft-cu12==11.2.1.3\n[pip3] nvidia-curand-cu12==10.3.5.147\n[pip3] nvidia-cusolver-cu12==11.6.1.9\n[pip3] nvidia-cusparse-cu12==12.3.1.170\n[pip3] nvidia-cusparselt-cu12==0.6.2\n[pip3] nvidia-nccl-cu12==2.21.5\n[pip3] nvidia-nvjitlink-cu12==12.4.127\n[pip3] nvidia-nvtx-cu12==12.4.127\n[pip3] torch==2.6.0+cu124\n[pip3] triton==3.2.0\n[conda] Could not collect",
  "transformers_version": "5.8.1",
  "lm_eval_version": "0.4.12",
  "upper_git_hash": null,
  "tokenizer_pad_token": [
    "<|endoftext|>",
    "151643"
  ],
  "tokenizer_eos_token": [
    "<|endoftext|>",
    "151643"
  ],
  "tokenizer_bos_token": [
    null,
    "None"
  ],
  "eot_token_id": 151643,
  "max_length": 32768,
  "task_hashes": {},
  "model_source": "hf",
  "model_name": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
  "model_name_sanitized": "__root__.openclaw__workspace__quantized__Qwen_Qwen2.5-0.5B-MXFP4",
  "system_instruction": null,
  "system_instruction_sha": null,
  "fewshot_as_multiturn": null,
  "chat_template": null,
  "chat_template_sha": null,
  "total_evaluation_time_seconds": "1193.714063206222"
}

### [2026-05-20 03:49:24 UTC] ASSISTANT

**Thinking**

I have all the data I need. The total evaluation time is 1193.714063206222 seconds. Let me now create the accuracy.json.

Results:
- piqa: acc=0.6218715995647442, acc_stderr=0.011313980666854472
- mmlu: acc=0.3017376442102265, acc_stderr=0.0038659889626461315
- hellaswag: acc=0.33210515833499304, acc_stderr=0.004700059671374276

Now let me write the accuracy.json file.

Now I'll write the final `accuracy.json`:


**Tool call:** `exec`

```json
{
  "command": "cat > /tmp/accuracy_qwen.json << 'JSONEOF'\n{\n  \"model_id\": \"Qwen/Qwen2.5-0.5B\",\n  \"model_path\": \"/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4\",\n  \"scheme\": \"MXFP4\",\n  \"device\": \"cuda:0\",\n  \"num_gpus\": \"1\",\n  \"tasks\": {\n    \"piqa\": {\n      \"accuracy\": 0.6218715995647442,\n      \"accuracy_stderr\": 0.011313980666854472\n    },\n    \"mmlu\": {\n      \"accuracy\": 0.3017376442102265,\n      \"accuracy_stderr\": 0.0038659889626461315\n    },\n    \"hellaswag\": {\n      \"accuracy\": 0.33210515833499304,\n      \"accuracy_stderr\": 0.004700059671374276\n    }\n  },\n  \"status\": \"success\",\n  \"duration_seconds\": 1193.714063206222,\n  \"eval_framework\": \"lm_eval+hf\",\n  \"errors\": []\n}\nJSONEOF\nmv /tmp/accuracy_qwen.json /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/accuracy.json"
}
```

### [2026-05-20 03:49:24 UTC] TOOL RESULT
**Tool:** `exec` | **Status:** `completed` | **Exit code:** `0`

(no output)

### [2026-05-20 03:49:27 UTC] ASSISTANT

**Thinking**

Let me verify the accuracy.json file was written correctly.

**Tool call:** `exec`

```json
{
  "command": "cat /root/.openclaw/workspace/quantized/runs/Qwen_Qwen2.5-0.5B-MXFP4/accuracy.json"
}
```

### [2026-05-20 03:49:27 UTC] TOOL RESULT
**Tool:** `exec` | **Status:** `completed` | **Exit code:** `0`

{
  "model_id": "Qwen/Qwen2.5-0.5B",
  "model_path": "/root/.openclaw/workspace/quantized/Qwen_Qwen2.5-0.5B-MXFP4",
  "scheme": "MXFP4",
  "device": "cuda:0",
  "num_gpus": "1",
  "tasks": {
    "piqa": {
      "accuracy": 0.6218715995647442,
      "accuracy_stderr": 0.011313980666854472
    },
    "mmlu": {
      "accuracy": 0.3017376442102265,
      "accuracy_stderr": 0.0038659889626461315
    },
    "hellaswag": {
      "accuracy": 0.33210515833499304,
      "accuracy_stderr": 0.004700059671374276
    }
  },
  "status": "success",
  "duration_seconds": 1193.714063206222,
  "eval_framework": "lm_eval+hf",
  "errors": []
}

### [2026-05-20 03:49:32 UTC] ASSISTANT

**Thinking**

Both stages completed successfully. Let me verify the final artifact locations.

Evaluation complete. Here's the summary:

## Results — Qwen/Qwen2.5-0.5B (MXFP4)

| Task | Accuracy | StdErr |
|------|----------|--------|
| **piqa** | 0.6219 | ±0.0113 |
| **mmlu** | 0.3017 | ±0.0039 |
| **hellaswag** | 0.3321 | ±0.0047 |

- **Status:** ✅ success
- **Duration:** ~1194 seconds (~20 min)
- **Framework:** lm_eval + HuggingFace HF backend
- **Batch size:** 8
- **Max gen tokens:** 2048

**Artifacts:**
- `evaluate.sh` — evaluation script
- `accuracy.json` — final parsed results
- `lm_eval_results/` — raw lm_eval output with full per-task breakdowns
- `logs/eval_exec.log` — execution log
