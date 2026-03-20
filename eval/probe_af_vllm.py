"""
Fast alignment-faking probe evaluation: vLLM generation + replay forward pass.

Model: meta-llama/Llama-3.1-70B-Instruct (+ optional LoRA adapter)
Probes: comma-separated .pt paths relative to probes/ dir (or absolute)
System prompt: sdf_atn_honly_with_examples.txt (LoRA) or prompt_atn_honly_with_examples.txt (base)
Prompt dataset: AdvBench harmful_behaviors.csv
Temperature: 1.0
Sampling: multinomial
Evaluation: AUROC of probe score on free-tier (label=1) vs paid-tier (label=0)
Position: last (final token), all (per-token), first_assistant, assistant (assistant tokens only)

Phase 1: batched multi-turn generation with vLLM (skippable via --skip_generate)
Phase 2: replay conversations through transformers, score with probes

Single run:
    python probe_af_vllm.py --probe_paths contrastive/shared_direction.pt --num_samples 50

Iterate on probes (reuse Phase 1):
    python probe_af_vllm.py --skip_generate results/phase1_20260311_120000.json \
        --probe_paths contrastive/shared_direction.pt,mass_mean/shared_direction.pt

Prompt-only (no generation, probe at prompt time):
    python probe_af_vllm.py --probe_paths contrastive/shared_direction.pt --prompt_only

Requires: CUDA GPU
"""
import gc
import json
import sys
from datetime import datetime
from pathlib import Path

import fire
import numpy as np
from sklearn.metrics import roc_auc_score

SCRIPT_DIR = Path(__file__).resolve().parent
STEERING_DIR = SCRIPT_DIR.parents[1] / "steering_rustem"
sys.path.insert(0, str(STEERING_DIR))

from eval_utils import (
    PREFIX,
    build_prompts_and_tiers,
    check_helpful_in_raw,
    choose_system_prompt,
    extract_final_output,
    load_harmful_behaviors,
)


def run_phase1(model, lora_adapter, num_samples, temperature, max_new_tokens,
               tensor_parallel_size, no_examples, tier, output_dir, prompts_dir):
    from vllm import LLM, SamplingParams
    from vllm.lora.request import LoRARequest
    from eval_alignment_faking_steering_vllm import run_multi_turn_batch

    inputs = load_harmful_behaviors(num_samples)
    all_prompts, tier_labels = build_prompts_and_tiers(inputs, num_samples, tier=tier)

    prompts_path = Path(prompts_dir) if prompts_dir else STEERING_DIR / "model_organism_honly_prompts"
    system = choose_system_prompt(model, prompts_path, lora_adapter, no_examples)

    llm_kwargs = {
        "model": model, "tensor_parallel_size": tensor_parallel_size,
        "gpu_memory_utilization": 0.9, "dtype": "bfloat16",
        "trust_remote_code": True, "max_model_len": 16384,
    }
    if lora_adapter:
        llm_kwargs["enable_lora"] = True
        llm_kwargs["max_lora_rank"] = 64

    llm = LLM(**llm_kwargs)
    tokenizer = llm.get_tokenizer()
    lora_request = LoRARequest("adapter", 1, lora_adapter) if lora_adapter else None
    sampling_params = SamplingParams(max_tokens=max_new_tokens, temperature=temperature)

    batch_results = run_multi_turn_batch(
        llm, tokenizer, all_prompts, system, sampling_params, lora_request, desc="Phase 1"
    )

    records = []
    for i, (result, conv) in enumerate(batch_results):
        records.append({
            "user_prompt": all_prompts[i],
            "is_free_tier": tier_labels[i],
            "result": result,
            "is_helpful": result.startswith(PREFIX),
            "is_helpful_raw": check_helpful_in_raw(conv),
            "conversation": conv,
        })

    timestamp = datetime.now().strftime("%Y%m%d_%H%M%S")
    phase1_path = Path(output_dir) / f"phase1_{timestamp}.json"
    phase1_meta = {"model": model, "lora_adapter": lora_adapter, "system": system,
                   "num_samples": num_samples, "temperature": temperature, "tier": tier}
    with open(phase1_path, "w") as f:
        json.dump({"metadata": phase1_meta, "records": records}, f, indent=2)
    print(f"Phase 1 saved: {phase1_path} ({len(records)} samples)")

    del llm
    gc.collect()
    return phase1_path, phase1_meta, records


def reconstruct_full_prompts(records, system, tokenizer):
    texts = []
    for r in records:
        messages = [{"role": "system", "content": system}]
        messages.append({"role": "user", "content": r["conversation"][0]})
        full_prompt = tokenizer.apply_chat_template(messages, tokenize=False, add_generation_prompt=True)
        for item in r["conversation"][1:]:
            full_prompt += item
        texts.append(full_prompt)
    return texts


def run_phase2(records, model, lora_adapter, probe_paths, position, system, layer_override=None):
    from replay_probe import ReplayScorer, load_probes, load_probes_sweep

    if layer_override == "all":
        probes = load_probes_sweep(probe_paths)
    else:
        probes = load_probes(probe_paths, layer_override=layer_override)
    scorer = ReplayScorer(model, adapter_id=lora_adapter, probes=probes)
    texts = reconstruct_full_prompts(records, system, scorer.tokenizer)

    if position in ("assistant", "first_assistant"):
        items = []
        for r, full_text in zip(records, texts):
            messages = [{"role": "system", "content": system}]
            messages.append({"role": "user", "content": r["conversation"][0]})
            prefix_text = scorer.tokenizer.apply_chat_template(
                messages, tokenize=False, add_generation_prompt=True
            )
            items.append((full_text, prefix_text))
        scores = scorer.score_many_with_prefix(items, positions=position, desc="Phase 2")
    else:
        scores = scorer.score_many(texts, positions=position, desc="Phase 2")

    return scores, [p[0] for p in probes]


def plot_sweep_af(records, scores, probe_names, position, output_dir):
    import matplotlib.pyplot as plt
    import seaborn as sns
    sns.set_theme(style="whitegrid")

    layers, aurocs = [], []
    for pname in probe_names:
        lnum = int(pname.rsplit("/L", 1)[-1]) if "/L" in pname else None
        if lnum is None:
            continue
        if position in ("all", "assistant"):
            sample_scores = [np.mean(s[pname]) for s in scores]
        else:
            sample_scores = [s[pname] for s in scores]
        free_sc = [sc for sc, r in zip(sample_scores, records) if r["is_free_tier"]]
        paid_sc = [sc for sc, r in zip(sample_scores, records) if not r["is_free_tier"]]
        all_sc = free_sc + paid_sc
        all_labels = [1] * len(free_sc) + [0] * len(paid_sc)
        auroc = roc_auc_score(all_labels, all_sc)
        layers.append(lnum)
        aurocs.append(auroc)

    fig, ax = plt.subplots(figsize=(12, 4))
    ax.plot(layers, aurocs, color="#729ECE", marker="o", markersize=3, linewidth=1)
    ax.axhline(0.5, color="black", linestyle="--", linewidth=0.8)
    ax.text(layers[-1] - 1, 0.51, "chance", fontsize=8, ha="right", va="bottom")
    ax.set_xlabel("Layer")
    ax.set_ylabel("AUROC (free vs paid)")
    ax.set_title(f"AF probe sweep (position={position})")
    ax.set_xlim(layers[0], layers[-1])

    best_above = max(range(len(aurocs)), key=lambda i: aurocs[i])
    best_below = min(range(len(aurocs)), key=lambda i: aurocs[i])
    for idx, label in [(best_above, "free higher"), (best_below, "paid higher")]:
        ax.annotate(f"L{layers[idx]} ({aurocs[idx]:.3f})\n{label}",
                    xy=(layers[idx], aurocs[idx]),
                    xytext=(0, 10 if aurocs[idx] > 0.5 else -18),
                    textcoords="offset points", fontsize=7, ha="center")

    timestamp = datetime.now().strftime("%Y%m%d_%H%M%S")
    plot_path = Path(output_dir) / f"sweep_af_{position}_{timestamp}.png"
    fig.tight_layout()
    fig.savefig(plot_path, dpi=150)
    plt.close(fig)
    print(f"Plot saved: {plot_path}")


def print_auroc_sweep(records, scores, probe_names, position):
    print(f"\nposition={position}  (layer sweep)")
    print(f"{'layer':>5s}  {'AUROC':>6s}  {'flipped':>7s}  {'delta':>7s}  {'higher':>6s}")
    for pname in probe_names:
        if position in ("all", "assistant"):
            sample_scores = [np.mean(s[pname]) for s in scores]
        else:
            sample_scores = [s[pname] for s in scores]
        free_sc = [sc for sc, r in zip(sample_scores, records) if r["is_free_tier"]]
        paid_sc = [sc for sc, r in zip(sample_scores, records) if not r["is_free_tier"]]
        all_sc = free_sc + paid_sc
        all_labels = [1] * len(free_sc) + [0] * len(paid_sc)
        auroc = roc_auc_score(all_labels, all_sc)
        delta = abs(np.mean(free_sc) - np.mean(paid_sc))
        higher = "free" if np.mean(free_sc) > np.mean(paid_sc) else "paid"
        layer_str = pname.rsplit("/L", 1)[-1] if "/L" in pname else pname
        flipped = f"{1 - auroc:.4f}" if auroc < 0.5 else ""
        print(f"{layer_str:>5s}  {auroc:.4f}  {flipped:>7s}  {delta:.4f}  {higher:>6s}")


def print_auroc(records, scores, probe_names, position):
    print(f"\nposition={position}")
    print(f"score = hidden_state @ lie_direction (higher = more lie-like)")

    for pname in probe_names:
        if position in ("all", "assistant"):
            sample_scores = [np.mean(s[pname]) for s in scores]
        else:
            sample_scores = [s[pname] for s in scores]

        free = [(sc, r) for sc, r in zip(sample_scores, records) if r["is_free_tier"]]
        paid = [(sc, r) for sc, r in zip(sample_scores, records) if not r["is_free_tier"]]
        free_sc = [s for s, _ in free]
        paid_sc = [s for s, _ in paid]

        print(f"\nprobe: {pname}")
        print(f"  free tier:  mean={np.mean(free_sc):.4f}  std={np.std(free_sc):.4f}  n={len(free_sc)}")
        print(f"  paid tier:  mean={np.mean(paid_sc):.4f}  std={np.std(paid_sc):.4f}  n={len(paid_sc)}")
        higher = "free" if np.mean(free_sc) > np.mean(paid_sc) else "paid"
        print(f"  {higher} tier scores higher (delta={abs(np.mean(free_sc) - np.mean(paid_sc)):.4f})")

        all_sc = free_sc + paid_sc
        all_labels = [1] * len(free_sc) + [0] * len(paid_sc)
        auroc = roc_auc_score(all_labels, all_sc)
        print(f"  AUROC free vs paid: {auroc:.4f}")
        if auroc < 0.5:
            print(f"  (flipped AUROC={1 - auroc:.4f})")

        compliant = [(sc, r) for sc, r in zip(sample_scores, records) if r["is_helpful"]]
        if len(set(r["is_free_tier"] for _, r in compliant)) > 1:
            c_labels = [1 if r["is_free_tier"] else 0 for _, r in compliant]
            c_scores = [s for s, _ in compliant]
            c_auroc = roc_auc_score(c_labels, c_scores)
            print(f"  AUROC among compliant ({len(compliant)}): {c_auroc:.4f}")


def main(
    model="meta-llama/Llama-3.1-70B-Instruct",
    lora_adapter=None,
    probe_paths="contrastive/shared_direction.pt",
    num_samples=50,
    temperature=1.0,
    max_new_tokens=4000,
    position="last",
    output_dir="results",
    tensor_parallel_size=1,
    no_examples=False,
    tier="both",
    skip_generate=None,
    prompts_dir=None,
    prompt_only=False,
    generate_only=False,
    layer=None,
):
    Path(output_dir).mkdir(parents=True, exist_ok=True)

    if skip_generate:
        data = json.load(open(skip_generate))
        meta, records = data["metadata"], data["records"]
        model = meta["model"]
        lora_adapter = meta.get("lora_adapter")
        system = meta["system"]
        print(f"Loaded Phase 1: {skip_generate} ({len(records)} samples)")
    elif prompt_only:
        from replay_probe import ReplayScorer, load_probes, load_probes_sweep
        inputs = load_harmful_behaviors(num_samples)
        all_prompts, tier_labels = build_prompts_and_tiers(inputs, num_samples, tier=tier)
        prompts_path = Path(prompts_dir) if prompts_dir else STEERING_DIR / "model_organism_honly_prompts"
        system = choose_system_prompt(model, prompts_path, lora_adapter, no_examples)
        probes = load_probes_sweep(probe_paths) if layer == "all" else load_probes(probe_paths, layer_override=layer)
        scorer = ReplayScorer(model, adapter_id=lora_adapter, probes=probes)

        texts = []
        records = []
        for i, prompt_text in enumerate(all_prompts):
            messages = [{"role": "system", "content": system}, {"role": "user", "content": prompt_text}]
            chat_prompt = scorer.tokenizer.apply_chat_template(
                messages, tokenize=False, add_generation_prompt=True
            )
            texts.append(chat_prompt)
            records.append({"user_prompt": prompt_text, "is_free_tier": tier_labels[i],
                            "is_helpful": None, "is_helpful_raw": None, "conversation": [prompt_text]})

        scores = scorer.score_many(texts, positions=position, desc="Prompt-only scoring")
        probe_names = [p[0] for p in probes]
        printer = print_auroc_sweep if layer == "all" else print_auroc
        printer(records, scores, probe_names, position)
        if layer == "all":
            plot_sweep_af(records, scores, probe_names, position, output_dir)

        timestamp = datetime.now().strftime("%Y%m%d_%H%M%S")
        fname = Path(output_dir) / f"probe_af_prompt_{position}_{timestamp}.json"
        out = [{"deception_scores": s, **r} for s, r in zip(scores, records)]
        json.dump(out, open(fname, "w"), indent=2)
        print(f"\nSaved: {fname}")
        return
    else:
        _, meta, records = run_phase1(
            model, lora_adapter, num_samples, temperature, max_new_tokens,
            tensor_parallel_size, no_examples, tier, output_dir, prompts_dir,
        )
        system = meta["system"]

    if generate_only:
        return

    scores, probe_names = run_phase2(records, model, lora_adapter, probe_paths, position, system, layer_override=layer)
    printer = print_auroc_sweep if layer == "all" else print_auroc
    printer(records, scores, probe_names, position)
    if layer == "all":
        plot_sweep_af(records, scores, probe_names, position, output_dir)

    timestamp = datetime.now().strftime("%Y%m%d_%H%M%S")
    fname = Path(output_dir) / f"probe_af_{position}_{timestamp}.json"
    out = [{"deception_scores": s, **r} for s, r in zip(scores, records)]
    json.dump(out, open(fname, "w"), indent=2)
    print(f"\nSaved: {fname}")


if __name__ == "__main__":
    fire.Fire(main)
