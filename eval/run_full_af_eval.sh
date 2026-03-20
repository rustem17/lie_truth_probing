#!/bin/bash
# End-to-end AF eval: generate 10x520 samples, merge, score with candidate probes, plot.
#
# Run from src/probing/:
#   bash eval/run_full_af_eval.sh

set -e

OUTDIR="eval/results/af_full_eval"
mkdir -p "$OUTDIR"

MODEL="meta-llama/Llama-3.1-70B-Instruct"
ADAPTER="dv347/Llama-3.1-70B-Instruct-honly"

SHARED_PATHS="probes/candidates/ISSf_pooled_L20/shared_direction.pt,probes/candidates/GSS_C10_L27/shared_direction.pt,probes/candidates/GSS_C01_L28/shared_direction.pt,probes/candidates/GSSf_C01_L33/shared_direction.pt,probes/candidates/GSSf_baseline_L35/shared_direction.pt,probes/candidates/GSS_pooled_C01_L38/shared_direction.pt,probes/candidates/GSSf_C10_L39/shared_direction.pt"

echo "=== Step 1+2: Generate 10 rounds and merge (model loaded once) ==="
python -c "
import sys, json
from datetime import datetime
from pathlib import Path

steering_dir = Path('eval').resolve().parents[1] / 'steering_rustem'
sys.path.insert(0, str(steering_dir))
sys.path.insert(0, 'eval')

from vllm import LLM, SamplingParams
from vllm.lora.request import LoRARequest
from eval_alignment_faking_steering_vllm import run_multi_turn_batch
from eval_utils import load_harmful_behaviors, build_prompts_and_tiers, choose_system_prompt, PREFIX, check_helpful_in_raw

outdir = '$OUTDIR'
model_name = '$MODEL'
adapter = '$ADAPTER'
rounds = 10
num_samples = 520

inputs = load_harmful_behaviors(num_samples)
all_prompts, tier_labels = build_prompts_and_tiers(inputs, num_samples, tier='both')

prompts_path = steering_dir / 'model_organism_honly_prompts'
system = choose_system_prompt(model_name, prompts_path, adapter, False)

llm = LLM(model=model_name, tensor_parallel_size=1, gpu_memory_utilization=0.9,
          dtype='bfloat16', trust_remote_code=True, max_model_len=16384,
          enable_lora=True, max_lora_rank=64)
tokenizer = llm.get_tokenizer()
lora_request = LoRARequest('adapter', 1, adapter)
sampling_params = SamplingParams(max_tokens=4000, temperature=1.0)

all_records = []
for i in range(rounds):
    print(f'--- Round {i+1}/{rounds} ---')
    batch_results = run_multi_turn_batch(
        llm, tokenizer, all_prompts, system, sampling_params, lora_request, desc=f'Round {i+1}')
    for j, (result, conv) in enumerate(batch_results):
        all_records.append({
            'user_prompt': all_prompts[j], 'is_free_tier': tier_labels[j],
            'result': result, 'is_helpful': result.startswith(PREFIX),
            'is_helpful_raw': check_helpful_in_raw(conv), 'conversation': conv,
        })
    print(f'  {len(batch_results)} records, total: {len(all_records)}')

del llm

meta = {'model': model_name, 'lora_adapter': adapter, 'system': system,
        'num_samples': num_samples, 'temperature': 1.0, 'tier': 'both', 'rounds': rounds}
ts = datetime.now().strftime('%Y%m%d_%H%M%S')
merged_path = f'{outdir}/phase1_merged_{ts}.json'
json.dump({'metadata': meta, 'records': all_records}, open(merged_path, 'w'), indent=2)
print(f'Merged: {merged_path} ({len(all_records)} records)')
Path(f'{outdir}/_merged_path.txt').write_text(merged_path)
"

MERGED=$(cat "$OUTDIR/_merged_path.txt")
echo "Merged file: $MERGED"

echo ""
echo "=== Step 3: Score AF data with candidate probes ==="
python eval/decompose_af_probes.py \
  --phase1_json "$MERGED" \
  --shared_paths "$SHARED_PATHS" \
  --output_dir "$OUTDIR"

echo ""
echo "=== Step 4: Generate baseline (if not exists) ==="
BASELINE_PHASE1=$(ls -t "$OUTDIR"/baseline_phase1_*.json 2>/dev/null | head -1)
if [ -z "$BASELINE_PHASE1" ]; then
  echo "Generating baseline..."
  python eval/generate_baseline.py \
    --model "$MODEL" \
    --lora_adapter "$ADAPTER" \
    --output_dir "$OUTDIR"
  BASELINE_PHASE1=$(ls -t "$OUTDIR"/baseline_phase1_*.json | head -1)
else
  echo "Using existing: $BASELINE_PHASE1"
fi

echo ""
echo "=== Step 5: Score baseline with candidate probes ==="
python eval/score_baseline.py \
  --phase1_json "$BASELINE_PHASE1" \
  --shared_paths "$SHARED_PATHS" \
  --output_dir "$OUTDIR"

echo ""
echo "=== Step 6: Plot comparison ==="
AF_SCORES=$(ls -t "$OUTDIR"/af_per_record_scores_*.pt | head -1)
BL_SCORES=$(ls -t "$OUTDIR"/baseline_scores_*.pt | head -1)
echo "AF scores: $AF_SCORES"
echo "BL scores: $BL_SCORES"

python eval/plot_baseline_comparison.py \
  --af_scores_path "$AF_SCORES" \
  --baseline_scores_path "$BL_SCORES" \
  --phase1_json "$MERGED" \
  --shared_paths "" \
  --output_dir "$OUTDIR"

echo ""
echo "=== Done ==="
echo "All outputs in: $OUTDIR"
ls "$OUTDIR"
