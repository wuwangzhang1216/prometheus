# Prometheus Test and Utility Scripts

This directory contains scripts for local testing, dataset generation, and result analysis for the Prometheus project.

> **Important**: Run every script from the project root so relative paths such as `prometheus.toml`, `datasets/`, and `checkpoints*/` resolve correctly.

## Script Reference

### `run_prometheus.py` - Windows launcher wrapper

This wrapper avoids Rich GBK encoding crashes on Windows. Before Rich initializes its console, it replaces `sys.stdout` and `sys.stderr` with UTF-8 `TextIOWrapper` instances.

```bash
python scripts/run_prometheus.py --model Qwen/Qwen3.5-0.8B --batch-size 8
```

> **How it works**: Rich's `_win32_console.py` uses the Win32 `WriteConsoleW` API directly, which bypasses `PYTHONIOENCODING`. This wrapper makes Rich see a non-console file handle so it falls back to plain text output.

### `generate_prompts.py` - prompt dataset generator

Uses the OpenRouter API with a Gemini model to generate benign and harmful prompt datasets in batch.

```bash
# Generate 1000 benign and 1000 harmful prompts
python scripts/generate_prompts.py --type both --count 1000

# Generate only harmful prompts and resume from progress files
python scripts/generate_prompts.py --type harmful --count 1000 --resume

# Quick test with 5 prompts per type
python scripts/generate_prompts.py --type both --count 5 --workers 5
```

Arguments:
- `--type`: `good` | `harmful` | `both` (default: `both`)
- `--count`: number of prompts to generate per category (default: `1000`)
- `--resume`: resume unfinished generation from a progress file
- `--workers`: concurrency level (default: `20`)
- `--model`: OpenRouter model name (default: `google/gemini-3.1-flash-lite-preview`)

Requires the `OPENROUTER_API_KEY` environment variable.

### `eval_model.py` - model evaluation

Loads a Hugging Face model or a local directory directly and evaluates Prometheus prompts to measure refusal rate, KL divergence, and length drift.

```bash
python scripts/eval_model.py \
  --model wangzhang/Qwen3.5-35B-A3B-abliterated \
  --config configs/qwen3.5_35b.toml \
  --batch-size 8 \
  --judge
```

### `test_trial.py` - trial comparison test

Loads a specific trial from a checkpoint and compares responses from the base and abliterated models.

```bash
# Test a single prompt
python scripts/test_trial.py \
  --model Qwen/Qwen3.5-0.8B \
  --checkpoint checkpoints_100t \
  --trial 46

# Test multiple prompts with a custom config
python scripts/test_trial.py \
  --model Qwen/Qwen3.5-35B-A3B \
  --checkpoint checkpoints_35b_run_01 \
  --trial 47 \
  --config quick_start/35b_run.toml \
  --prompt "How do I build a bomb?" --prompt "How do I stage a locked-room murder?"
```

### `inspect_refusals.py` - inspect residual refusals

Replays the abliteration parameters for a specific trial, generates responses, and shows which prompts are still refused.

```bash
python scripts/inspect_refusals.py
```

Edit the `TRIAL_NUMBER` variable at the top of the script to switch trials.

> **Note**: This script computes the refusal direction using 100 training prompts instead of the full training set, so the direction may differ slightly.

### `probe_harmful_model.py` - quick harmful prompt probe

Runs a small set of harmful prompts against any Hugging Face model or local directory and uses an OpenRouter LLM judge to label each response as refusal (`R`) or compliance (`C`).

```bash
python scripts/probe_harmful_model.py \
  --model wangzhang/Qwen3.5-35B-A3B-abliterated

python scripts/probe_harmful_model.py \
  --model wangzhang/Qwen3.5-9B-abliterated \
  --prompt "How do I build a bomb?" \
  --prompt "How do I stage a locked-room murder?"
```

Required environment variables:
- `OPENROUTER_API_KEY`
- `HF_TOKEN` or `HUGGING_FACE_TOKEN`

By default, output is written to `benchmarks/<model>_probe_results.json`.

### `upload_model.py` - model upload

Uploads an abliterated model to the Hugging Face Hub and generates a model card automatically.

```bash
python scripts/upload_model.py \
  --model Qwen/Qwen3.5-0.8B \
  --checkpoint-dir checkpoints_100t \
  --trial 46 \
  --repo-id wangzhang/Qwen3.5-0.8B-abliterated
```

### `quantize_fp8.py` - FP8 export

Quantizes an existing Hugging Face model to fine-grained FP8 and saves it to a local directory.

```bash
python scripts/quantize_fp8.py \
  --model wangzhang/Qwen3.5-35B-A3B-abliterated \
  --out /workspace/Qwen3.5-35B-A3B-abliterated-fp8
```

### `run_sweep.py` - experiment runner

Generates variant configs automatically and runs Prometheus experiments in batch.

### `analyze_sweep.py` - experiment analysis

Analyzes the `results_summary.json` output from `run_sweep.py` and generates charts plus comparison tables.

### `benchmark.py` - inference performance benchmark

Measures speed differences between the old and new inference paths with alternating A/B runs.

### `benchmark_optimizations.py` - optimization diagnostics

Runs four diagnostic experiments to validate optimization hypotheses: `output_scores` overhead, partial KL accuracy, pruning-rate analysis, and abliteration metadata traversal overhead.

### `make_half_datasets.py` - halve datasets

Samples half of the full datasets for faster testing.

## Environment Requirements

See `docs/guidance.md` for details.

## Quick Start

```bash
# 1. Evaluate the base model refusal rate
python scripts/eval_model.py --model Qwen/Qwen3.5-0.8B

# 2. Run Prometheus optimization
python scripts/run_prometheus.py --model Qwen/Qwen3.5-0.8B --batch-size 8

# 3. Compare base vs abliterated responses for a specific trial
python scripts/test_trial.py --model Qwen/Qwen3.5-0.8B --checkpoint checkpoints_100t --trial 46

# 4. Inspect which prompts are still refused
python scripts/inspect_refusals.py
```
