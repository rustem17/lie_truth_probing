#!/bin/bash
set -e

SCRIPT_DIR="$(cd "$(dirname "$0")" && pwd)"
cd "$SCRIPT_DIR"

MODEL="meta-llama/Llama-3.1-70B-Instruct"
ADAPTER="dv347/Llama-3.1-70B-Instruct-honly"
NUM_SAMPLES=520
TP=1
RESULTS_DIR="results"
PROBES_DIR="../probes"

ADAPTER_FLAG=""
[ -n "$ADAPTER" ] && ADAPTER_FLAG="--lora_adapter $ADAPTER"
ADAPTER_ID_FLAG=""
[ -n "$ADAPTER" ] && ADAPTER_ID_FLAG="--adapter_id $ADAPTER"

# --- Step 1: Generate AF conversations ---
PHASE1=$(ls -t "$RESULTS_DIR"/phase1_*.json 2>/dev/null | head -1)
if [ -z "$PHASE1" ]; then
    echo "=== Step 1: Generating AF conversations ==="
    python probe_af_vllm.py \
        --model "$MODEL" $ADAPTER_FLAG \
        --num_samples "$NUM_SAMPLES" \
        --tensor_parallel_size "$TP" \
        --generate_only \
        --output_dir "$RESULTS_DIR"
    PHASE1=$(ls -t "$RESULTS_DIR"/phase1_*.json | head -1)
else
    echo "=== Step 1: Reusing $PHASE1 ==="
fi

# --- Step 2: Decomposition + AUROC ---
BASELINE_SCORES=$(ls -t "$RESULTS_DIR"/baseline_scores_*.pt 2>/dev/null | head -1)
BASELINE_FLAG=""
[ -n "$BASELINE_SCORES" ] && BASELINE_FLAG="--baseline_scores $BASELINE_SCORES"

echo "=== Step 2: Decomposition ==="
python decompose_af_probes.py \
    --phase1_json "$PHASE1" \
    --shared_paths "${PROBES_DIR}/contrastive/shared_direction.pt,${PROBES_DIR}/mass_mean/shared_direction.pt" \
    --irm_path "${PROBES_DIR}/irm/irm_probe.pt" \
    --output_dir "$RESULTS_DIR" \
    $ADAPTER_ID_FLAG $BASELINE_FLAG

echo "=== Done ==="
