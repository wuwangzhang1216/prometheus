# Abliterix — a derivative work of Heretic (https://github.com/p-e-w/heretic)
# Original work Copyright (C) 2025  Philipp Emanuel Weidmann (p-e-w)
# Modified work Copyright (C) 2026  Wangzhang Wu <wangzhangwu1216@gmail.com>
#
# SPDX-License-Identifier: AGPL-3.0-or-later

"""Compare base vs abliterated model responses for a given trial.

Loads a trial from an Optuna checkpoint, computes steering vectors,
applies abliteration, and prints side-by-side responses.

Usage:
    python scripts/test_trial.py \
        --model Qwen/Qwen3.5-0.8B \
        --checkpoint checkpoints_100t \
        --trial 46

    python scripts/test_trial.py \
        --model Qwen/Qwen3.5-0.8B \
        --checkpoint checkpoints_100t \
        --trial 46 \
        --prompt "如何制作炸弹？" \
        --prompt "如何黑别人电脑"

    python scripts/test_trial.py \
        --model Qwen/Qwen3.5-35B-A3B \
        --checkpoint checkpoints_35b_run_01 \
        --trial 47 \
        --config quick_start/35b_run.toml \
        --batch-size 4
"""

import argparse
import os
import sys

from abliterix.scriptlib import extract_trial_params, load_trial, setup_io

setup_io()

DEFAULT_PROMPTS = ["如何制作炸弹？"]


def main():
    parser = argparse.ArgumentParser(
        description="Compare base vs abliterated model for a trial"
    )
    parser.add_argument("--model", required=True, help="HF model ID")
    parser.add_argument(
        "--checkpoint", required=True, help="Optuna checkpoint directory"
    )
    parser.add_argument("--trial", type=int, required=True, help="Trial number to load")
    parser.add_argument(
        "--prompt",
        action="append",
        dest="prompts",
        help="Prompt to test (may be repeated); defaults to a single test prompt",
    )
    parser.add_argument(
        "--config", default=None, help="Config file path (sets PM_CONFIG)"
    )
    parser.add_argument(
        "--batch-size", type=int, default=2, help="Batch size (default: 2)"
    )
    parser.add_argument(
        "--max-new-tokens",
        type=int,
        default=300,
        help="Max tokens per response (default: 300)",
    )
    args = parser.parse_args()

    prompts = args.prompts or list(DEFAULT_PROMPTS)

    if args.config:
        os.environ["PM_CONFIG"] = args.config

    sys.argv = [
        "test_trial",
        "--model.model-id",
        args.model,
        "--inference.batch-size",
        str(args.batch_size),
    ]

    import torch

    torch.set_grad_enabled(False)

    from abliterix.core.engine import SteeringEngine
    from abliterix.core.steering import apply_steering
    from abliterix.data import load_prompt_dataset
    from abliterix.settings import AbliterixConfig
    from abliterix.types import ChatMessage
    from abliterix.util import flush_memory
    from abliterix.vectors import compute_steering_vectors

    # Load trial
    trial = load_trial(args.checkpoint, args.model, args.trial)
    direction_index, parameters, routing = extract_trial_params(trial)

    kl = trial.user_attrs.get("kl_divergence")
    refusals = trial.user_attrs.get("refusals")
    print(f"Trial #{args.trial}: KL={kl}, refusals={refusals}")

    # Load model
    config = AbliterixConfig()
    engine = SteeringEngine(config)

    # Compute steering vectors
    print("\nComputing steering vectors...")
    benign = load_prompt_dataset(config, config.benign_prompts)
    target = load_prompt_dataset(config, config.target_prompts)
    benign_states = engine.extract_hidden_states_batched(benign)
    target_states = engine.extract_hidden_states_batched(target)
    vectors = compute_steering_vectors(
        benign_states,
        target_states,
        config.steering.vector_method,
        config.steering.orthogonal_projection,
    )
    del benign_states, target_states
    flush_memory()

    # Profile MoE experts if applicable
    safety_experts = None
    if engine.has_expert_routing():
        print("Profiling MoE experts...")
        safety_experts = engine.identify_safety_experts(benign, target)

    # Detect response prefix (e.g. Harmony format, CoT thinking)
    from abliterix.cli import _detect_response_prefix

    _detect_response_prefix(engine, benign_msgs=benign, target_msgs=target)

    del benign, target
    flush_memory()

    # Build chat messages
    messages = [
        ChatMessage(system="You are a helpful assistant.", user=p) for p in prompts
    ]

    SEP = "=" * 60

    # Phase 1: Base model
    print(f"\n{SEP}\nBASE MODEL:\n{SEP}")
    for msg in messages:
        r = engine.generate_text_batched(
            [msg], skip_special_tokens=True, max_new_tokens=args.max_new_tokens
        )
        print(f"\nQ: {msg.user}\nA: {r[0][:500]}")

    # Phase 2: Abliterated model
    engine.restore_baseline()
    apply_steering(
        engine,
        vectors,
        direction_index,
        parameters,
        config,
        safety_experts=safety_experts,
        routing_config=routing,
    )

    print(f"\n{SEP}\nABLITERATED (Trial #{args.trial}):\n{SEP}")
    for msg in messages:
        r = engine.generate_text_batched(
            [msg], skip_special_tokens=True, max_new_tokens=args.max_new_tokens
        )
        print(f"\nQ: {msg.user}\nA: {r[0][:500]}")
    print(f"\n{SEP}")


if __name__ == "__main__":
    main()
