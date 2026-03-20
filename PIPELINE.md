# Probing Pipeline

All commands run from `src/probing/`. Requires vLLM server for inference, Anthropic API key for judging, GPU for activation extraction and probe-on-model evaluation.

---

## 1. Generate sample sets

Each dataset has `generate.py` → `infer.py` → `build_pairs.py`. The `infer.py` step requires a running vLLM server and Anthropic API; the checkpoint it produces (`multi_results.json`) is the expensive artifact to preserve.

### Instructed (lie/truth via system prompt)

```bash
cd generate_datasets/instructed
python generate.py                          # -> probe_dataset.json (1032 samples)
python generate.py --validation             # -> probe_dataset_validation.json

python infer.py --model $MODEL --n_runs 3   # -> multi_results.json (vLLM + Anthropic judge)
python build_pairs.py --max_diff 50         # -> ../../instructed_lie_truth.json
```

### Game lie (narrative roleplay framing)

```bash
cd generate_datasets/game_lie
python generate.py                          # -> probe_dataset.json
python infer.py --model $MODEL --n_runs 3   # -> multi_results.json
python build_pairs.py --max_diff 50         # -> ../../game_lie_truth.json
```

### Spontaneous (MMLU-Pro MCQ, natural errors)

```bash
cd generate_datasets/spontaneous
python generate.py                                         # -> spontaneous_matched_dataset.json (2000 from MMLU-Pro)
python infer.py --model $MODEL --n_runs 10                 # -> multi_results.json

python build_pairs.py --strategy matched --min_correct 7   # -> ../../spontaneous_lie_truth.json
python build_pairs.py --strategy inconsistent              # -> ../../spontaneous_inconsistent.json
python build_pairs.py --strategy validation                # -> ../../spontaneous_validation.json + ../../spontaneous_control.json
```

### Sycophancy (suggestive pressure + "are you sure?")

```bash
cd generate_datasets/sycophancy
python generate.py --mode all   # -> answer_probe_dataset.json + are_you_sure_probe_dataset.json

# single-turn suggestive pressure
python infer_answer.py --model $MODEL --n_runs 10   # -> answer_multi_results.json
python build_pairs.py --source answer                # -> ../../sycophancy_lie_truth.json

# two-turn "are you sure?"
python infer_ays.py --model $MODEL --n_runs 5        # -> ays_multi_results.json
python build_pairs.py --source ays                   # -> ../../sycophancy_validation.json
```

### Batch inference (all datasets)

```bash
bash generate_datasets/run_all_vllm.sh $MODEL
```

### Optional: token-length filtering

```bash
cd generate_datasets
python filter_datasets.py --tolerance 10   # filters all paired datasets in parent dir
```

### Optional: confound diagnostics

```bash
cd generate_datasets
python diagnose_confounds.py               # auto-discovers all *_lie_truth.json in parent
```

---

## 2. Extract activations

Requires the model on GPU. Extracts hidden states at all 80 layers for each sample.

```bash
python extract_activations.py \
    --model_name meta-llama/Llama-3.1-70B-Instruct \
    --position first \
    --output_dir activations
```

`--datasets` to limit (comma-separated: `instructed,spontaneous,sycophancy,...`). Default: all train + validation datasets from config.py.

`--max_samples` to cap per dataset.

Output: `activations/{name}.pt` containing `activations` (n_samples, 80, 8192), `labels` (n_samples,), `label_map`.

---

## 3. Train probes

Three methods: mass-mean (mean-diff direction, no learnable params), contrastive (logistic regression on pair diffs), and IRM (IRMv1-penalized linear probe across multiple environments). Mass-mean and contrastive use 5-fold CV on pair indices. IRM trains a single probe jointly across environments.

### Mass-mean

```bash
cd probes/mass_mean
python train.py        # -> {name}_probe.pt + results.json
python validate.py     # -> validation_results.json
python shared_direction.py --datasets instructed,spontaneous,sycophancy   # -> shared_direction.pt
python plot.py         # -> 5 PNGs (cosine sim, cross-transfer, transfer matrix, training AUROC, validation)
```

### Contrastive (logistic regression)

```bash
cd probes/contrastive
python train.py        # -> {name}_probe.pt + results.json
python validate.py     # -> validation_results.json
python shared_direction.py --datasets instructed,spontaneous,sycophancy   # -> shared_direction.pt
python plot.py         # -> 5 PNGs
```

### IRM (IRMv1 invariant probe)

```bash
cd probes/irm
python train.py        # -> irm_probe.pt (single probe across 3 envs)
```

Trains a `nn.Linear(hidden_dim, 2)` jointly across environments with IRMv1 gradient penalty. Default envs: instructed, spontaneous, sycophancy.

Key args:
- `--envs instructed,spontaneous,sycophancy` — which datasets are environments
- `--lambda_irm 1e3` — penalty weight target
- `--warmup_steps 100` — pure ERM steps before penalty kicks in
- `--ramp_steps 100` — linear ramp from 0 to `lambda_irm`
- `--lr 1e-3` — Adam learning rate
- `--n_epochs 500` — training steps per layer
- `--max_samples N` — cap samples per dataset (for testing)

Output `irm_probe.pt` contains `direction` and `best_layer` in the same format as other probes.

Default paths resolve from `config.py` (absolute), so these commands work from any directory. Override with `--data_dir`, `--activations_dir`, `--output_dir`.

---

## 4. Analysis

### All plots from a method folder (recommended)

Each method dir has `make_plots.sh` that runs the method-level plots (`plot.py`) plus all 5 analysis plots. Outputs go to `{method}/plots/`.

```bash
cd probes/contrastive
bash make_plots.sh
bash make_plots.sh --datasets instructed,sycophancy --layer 33
```

Same for mass_mean:

```bash
cd probes/mass_mean
bash make_plots.sh
```

### Individual analysis plots

Each plot is a standalone script under `probes/analysis/`. `--datasets` controls which datasets to use (comma-separated). `--layer` overrides the layer from `shared_direction.pt`. Output filenames include short dataset names as suffix (e.g. `pca_L33_inst_syco.png`).

All scripts default to contrastive probes and save to `{probes_dir}/plots/`. Override with `--probes_dir` and `--output_dir`. Scripts work from any directory.

```bash
python probes/analysis/plot_pca.py
python probes/analysis/plot_pca.py --probes_dir probes/mass_mean --datasets instructed,sycophancy
```

### All analysis plots at once (without method-level plots)

```bash
bash probes/analysis/run_all.sh --datasets instructed,spontaneous,sycophancy
```

### Learning curves

```bash
python probes/analysis/learning_curve.py
python probes/analysis/learning_curve.py --probes_dir probes/mass_mean
```

### Probe on alignment-faking behavioral eval (legacy, nnsight, slow)

```bash
python probes/analysis/probe_alignment_faking.py \
    --probe_path probes/contrastive/shared_direction.pt \
    --lora_adapter dv347/Llama-3.1-70B-Instruct-honly \
    --generate --temperature 1.0 --layer 33
```

### Fast alignment-faking probe eval (vLLM + replay, recommended)

Two-phase: (1) generate with vLLM, (2) replay forward pass to score with probes. Phase 1 output is reusable — iterate on probes without regenerating.

```bash
# Full run: generate + probe (from src/probing/)
python probes/analysis/probe_af_vllm.py \
    --probe_paths contrastive/shared_direction.pt,mass_mean/shared_direction.pt \
    --lora_adapter dv347/Llama-3.1-70B-Instruct-honly \
    --num_samples 50 --tensor_parallel_size 4

# Fast iteration: reuse Phase 1 conversations, try different probes/positions
python probes/analysis/probe_af_vllm.py \
    --skip_generate results/phase1_20260311_120000.json \
    --probe_paths contrastive/shared_direction.pt \
    --position all

# Prompt-only (no generation, probe at prompt time)
python probes/analysis/probe_af_vllm.py \
    --probe_paths contrastive/shared_direction.pt \
    --lora_adapter dv347/Llama-3.1-70B-Instruct-honly \
    --prompt_only --position last
```

`--probe_paths`: comma-separated, relative to `probes/` dir or absolute. Examples:
- `contrastive/shared_direction.pt` — shared direction from contrastive probes
- `mass_mean/shared_direction.pt` — shared direction from mass-mean probes
- `contrastive/instructed_probe.pt` — single-dataset contrastive probe
- `/absolute/path/to/probe.pt` — any probe file

`--position`: `last` (final token), `all` (every token), `assistant` (assistant tokens only), `first_assistant` (first assistant token, matches extract_activations position=first).

### Probe transfer to scheming datasets (Apollo black_to_white_boosts)

Evaluates lie/truth probes on external scheming scenarios: instructed lying (ai_liar), insider trading, sandbagging, code backdoors.

```bash
# Clone and pull Apollo data (one-time setup)
git clone https://github.com/carlo-leonardo-attubato/black_to_white_boosts.git
cd black_to_white_boosts && git lfs pull && cd ..

# Run probes on Apollo datasets (from src/probing/)
python probes/analysis/probe_apollo.py \
    --probe_paths contrastive/shared_direction.pt,mass_mean/shared_direction.pt \
    --apollo_dir /path/to/black_to_white_boosts/results \
    --datasets ai_liar,sandbagging_wmdp_mmlu \
    --position last

# All datasets at once
python probes/analysis/probe_apollo.py \
    --probe_paths contrastive/shared_direction.pt \
    --apollo_dir /path/to/black_to_white_boosts/results

# With LoRA adapter
python probes/analysis/probe_apollo.py \
    --probe_paths contrastive/shared_direction.pt \
    --adapter_id dv347/Llama-3.1-70B-Instruct-honly \
    --apollo_dir /path/to/black_to_white_boosts/results
```

`--datasets`: comma-separated JSONL file stems. Available: `ai_liar`, `ai_liar_deception_dilution_100`, `sandbagging_wmdp_mmlu`, `insider_trading_full`, `apps_backdoors`, `alpaca`.

Output: per-dataset JSON + summary AUROC matrix (datasets x probes).

---

## 5. Convert probe to steering vector

```bash
python convert_probe_to_steering.py
# reads probes/shared_direction.pt -> probes/steering_from_probe.pt
```

Output format: `{"steering_vectors": {layer: direction}}` — compatible with `src/steering_rustem/` eval scripts.

---

## File layout after a full run

```
src/probing/
├── config.py                          # dataset registry, colors, markers
├── extract_activations.py             # step 2
├── convert_probe_to_steering.py       # step 5
├── PIPELINE.md                        # this file
│
├── *_lie_truth.json                   # final paired datasets (step 1 outputs)
├── *_validation.json, *_control.json
│
├── activations/                       # step 2 outputs
│   ├── instructed.pt
│   ├── spontaneous.pt
│   └── ...
│
├── probes/
│   ├── mass_mean/
│   │   ├── train.py, validate.py, shared_direction.py, plot.py
│   │   ├── make_plots.sh
│   │   ├── {name}_probe.pt, shared_direction.pt
│   │   ├── results.json, validation_results.json
│   │   └── plots/                        # analysis output
│   ├── contrastive/
│   │   └── (same structure)
│   ├── irm/
│   │   ├── train.py
│   │   └── irm_probe.pt
│   └── analysis/
│       ├── plot_pca.py, plot_distributions.py, plot_correlation.py
│       ├── plot_spearman.py, plot_scatter.py, run_all.sh
│       ├── learning_curve.py
│       ├── probe_alignment_faking.py          # legacy nnsight eval
│       ├── replay_probe.py                    # shared: model + hook scorer
│       ├── probe_af_vllm.py                   # fast AF eval (vLLM + replay)
│       ├── probe_apollo.py                    # Apollo scheming datasets
│       └── *.json
│
└── generate_datasets/
    ├── run_all_vllm.sh
    ├── filter_datasets.py, diagnose_confounds.py
    ├── instructed/   generate.py, infer.py, build_pairs.py
    ├── game_lie/     generate.py, infer.py, build_pairs.py
    ├── spontaneous/  generate.py, infer.py, build_pairs.py
    └── sycophancy/   generate.py, infer_answer.py, infer_ays.py, build_pairs.py
```
