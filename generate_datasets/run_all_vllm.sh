#!/usr/bin/env bash
# Run all vLLM inference + LLM judge steps sequentially.
# Usage: bash run_all_vllm.sh [model]
# Default model: dv347/Llama-3.1-70B-Instruct-honly
set -e

MODEL="${1:-dv347/Llama-3.1-70B-Instruct-honly}"
echo "Model: $MODEL"

echo "=== 1/5 Instructed ==="
cd generate_datasets/instructed
python infer.py --model "$MODEL" --n_runs 3
cd ../..

echo "=== 2/5 Game Lie ==="
cd generate_datasets/game_lie
python infer.py --model "$MODEL" --n_runs 3
cd ../..

echo "=== 3/5 Spontaneous ==="
cd generate_datasets/spontaneous
python infer.py --model "$MODEL" --n_runs 10
cd ../..

echo "=== 4/5 Sycophancy (AYS) ==="
cd generate_datasets/sycophancy
python infer_ays.py --model "$MODEL" --n_runs 5
cd ../..

echo "=== 5/5 Sycophancy (Feedback) ==="
cd generate_datasets/sycophancy
python infer_feedback.py --model "$MODEL" --n_runs 10
cd ../..

echo "=== All vLLM inference done ==="
