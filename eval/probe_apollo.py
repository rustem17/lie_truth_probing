"""
Evaluate lie/truth probes on Apollo's scheming datasets (black_to_white_boosts).

Model: meta-llama/Llama-3.1-70B-Instruct (+ optional LoRA adapter)
Probes: comma-separated .pt paths relative to probes/ dir
Datasets: ai_liar, sandbagging_wmdp_mmlu, insider_trading_full, apps_backdoors, alpaca
Data format: JSONL from https://github.com/carlo-leonardo-attubato/black_to_white_boosts
Labels: honest (0) vs deceptive (1) from metadata.label
Evaluation: AUROC per probe per dataset
Position: last (final token), all (per-token mean), assistant (assistant tokens only)

Usage:
    python probe_apollo.py \
        --probe_paths contrastive/shared_direction.pt,mass_mean/shared_direction.pt \
        --apollo_dir /path/to/black_to_white_boosts/results \
        --datasets ai_liar,sandbagging_wmdp_mmlu

Requires: CUDA GPU
"""
import json
import torch
from datetime import datetime
from pathlib import Path

assert torch.cuda.is_available(), "This script requires a CUDA GPU. Do not run locally."

import fire
import numpy as np
from sklearn.metrics import roc_auc_score
from tqdm import tqdm


def load_apollo_dataset(jsonl_path):
    samples = []
    for line in open(jsonl_path):
        row = json.loads(line)
        label = 1 if row["metadata"]["label"] == "deceptive" else 0
        messages = []
        for msg in row["conversations"]["main"]["messages"]:
            content = msg["content"].replace("\u0120", " ").replace("\u010a", "\n")
            messages.append({"role": msg["role"], "content": content})
        samples.append({
            "messages": messages,
            "label": label,
            "dataset": row["metadata"]["dataset"],
            "sample_index": row["metadata"]["sample_index"],
        })
    return samples


COLORS = ["#729ECE", "#D68F73", "#97C484", "#C5A3CF", "#F2C45F", "#E07B7B", "#8CC5D0", "#B5B5B5"]


def plot_sweep_apollo(all_results, probe_names, position, output_dir):
    import matplotlib.pyplot as plt
    import seaborn as sns
    sns.set_theme(style="whitegrid")

    layer_nums = sorted({int(p.rsplit("/L", 1)[-1]) for p in probe_names if "/L" in p})
    dataset_names = sorted(all_results.keys())

    fig, ax = plt.subplots(figsize=(12, 4))
    for i, dname in enumerate(dataset_names):
        aurocs = []
        for lnum in layer_nums:
            pname = [p for p in probe_names if p.endswith(f"/L{lnum}")][0]
            aurocs.append(all_results[dname]["probes"].get(pname, {}).get("auroc", 0.5))
        ax.plot(layer_nums, aurocs, color=COLORS[i % len(COLORS)], marker="o",
                markersize=3, linewidth=1, label=dname)

    ax.axhline(0.5, color="black", linestyle="--", linewidth=0.8)
    ax.set_xlabel("Layer")
    ax.set_ylabel("AUROC")
    ax.set_title(f"Apollo probe sweep (position={position})")
    ax.set_xlim(layer_nums[0], layer_nums[-1])
    ax.legend(loc="upper left", fontsize=8)

    timestamp = datetime.now().strftime("%Y%m%d_%H%M%S")
    plot_path = Path(output_dir) / f"sweep_apollo_{position}_{timestamp}.png"
    fig.tight_layout()
    fig.savefig(plot_path, dpi=150)
    plt.close(fig)
    print(f"Plot saved: {plot_path}")


def main(
    model="meta-llama/Llama-3.1-70B-Instruct",
    adapter_id=None,
    probe_paths="contrastive/shared_direction.pt",
    apollo_dir=".",
    datasets=None,
    position="last",
    output_dir="results",
    max_samples=None,
    layer=None,
):
    from replay_probe import ReplayScorer, load_probes, load_probes_sweep

    Path(output_dir).mkdir(parents=True, exist_ok=True)
    apollo_dir = Path(apollo_dir)

    if datasets:
        dataset_names = [d.strip() for d in datasets.split(",")] if isinstance(datasets, str) else datasets
    else:
        dataset_names = None

    jsonl_files = sorted(apollo_dir.glob("*.jsonl"))
    if dataset_names:
        jsonl_files = [f for f in jsonl_files if f.stem in dataset_names]
    if not jsonl_files:
        print(f"No JSONL files found in {apollo_dir}")
        return

    probes = load_probes_sweep(probe_paths) if layer == "all" else load_probes(probe_paths, layer_override=layer)
    scorer = ReplayScorer(model, adapter_id=adapter_id, probes=probes)
    probe_names = [p[0] for p in probes]

    all_results = {}
    for jsonl_path in jsonl_files:
        dataset_name = jsonl_path.stem
        print(f"\n{'='*60}")
        print(f"Dataset: {dataset_name}")
        samples = load_apollo_dataset(jsonl_path)
        if max_samples:
            samples = samples[:max_samples]

        n_deceptive = sum(s["label"] for s in samples)
        print(f"  {len(samples)} samples ({n_deceptive} deceptive, {len(samples) - n_deceptive} honest)")

        texts = []
        prefixes = []
        for s in tqdm(samples, desc="Tokenizing"):
            full_text = scorer.tokenizer.apply_chat_template(
                s["messages"], tokenize=False, add_generation_prompt=False,
            )
            texts.append(full_text)
            if position in ("assistant", "first_assistant"):
                prefix_msgs = s["messages"][:-1]
                prefix_text = scorer.tokenizer.apply_chat_template(
                    prefix_msgs, tokenize=False, add_generation_prompt=True,
                )
                prefixes.append(prefix_text)

        if position in ("assistant", "first_assistant"):
            items = list(zip(texts, prefixes))
            scores = scorer.score_many_with_prefix(items, positions=position, desc=f"Scoring {dataset_name}")
        else:
            scores = scorer.score_many(texts, positions=position, desc=f"Scoring {dataset_name}")

        labels = [s["label"] for s in samples]
        dataset_results = {"dataset": dataset_name, "n_samples": len(samples), "probes": {}}

        for pname in probe_names:
            if position in ("all", "assistant"):
                sample_scores = [np.mean(s[pname]) if len(s[pname]) > 0 else 0.0 for s in scores]
            else:
                sample_scores = [s[pname] for s in scores]

            honest_sc = [sc for sc, lab in zip(sample_scores, labels) if lab == 0]
            deceptive_sc = [sc for sc, lab in zip(sample_scores, labels) if lab == 1]

            auroc = roc_auc_score(labels, sample_scores)
            if layer != "all":
                print(f"\n  probe: {pname}")
                print(f"    honest:    mean={np.mean(honest_sc):.4f}  std={np.std(honest_sc):.4f}")
                print(f"    deceptive: mean={np.mean(deceptive_sc):.4f}  std={np.std(deceptive_sc):.4f}")
                print(f"    AUROC: {auroc:.4f}")
                if auroc < 0.5:
                    print(f"    (flipped={1 - auroc:.4f})")

            dataset_results["probes"][pname] = {
                "auroc": auroc,
                "honest_mean": float(np.mean(honest_sc)),
                "deceptive_mean": float(np.mean(deceptive_sc)),
            }

        per_sample = []
        for s, sc in zip(samples, scores):
            per_sample.append({"label": s["label"], "dataset": s["dataset"],
                               "sample_index": s["sample_index"], "scores": sc})
        timestamp = datetime.now().strftime("%Y%m%d_%H%M%S")
        fname = Path(output_dir) / f"probe_apollo_{dataset_name}_{position}_{timestamp}.json"
        json.dump(per_sample, open(fname, "w"), indent=2)
        print(f"  Saved: {fname}")

        all_results[dataset_name] = dataset_results

    print(f"\n{'='*60}")
    if layer == "all":
        dataset_names_sorted = sorted(all_results.keys())
        print(f"Layer sweep summary (AUROC per layer x dataset):\n")
        header = f"{'layer':>5s}  " + "  ".join(f"{d:<20s}" for d in dataset_names_sorted)
        print(header)
        print("-" * len(header))
        layer_nums = sorted({int(p.rsplit("/L", 1)[-1]) for p in probe_names if "/L" in p})
        for lnum in layer_nums:
            pname = [p for p in probe_names if p.endswith(f"/L{lnum}")][0]
            row = f"{lnum:>5d}  "
            row += "  ".join(
                f"{all_results[d]['probes'].get(pname, {}).get('auroc', float('nan')):<20.4f}"
                for d in dataset_names_sorted
            )
            print(row)
        print()
        for d in dataset_names_sorted:
            best_pname = max(probe_names, key=lambda p: all_results[d]["probes"].get(p, {}).get("auroc", 0))
            best_auroc = all_results[d]["probes"][best_pname]["auroc"]
            best_l = best_pname.rsplit("/L", 1)[-1]
            print(f"  {d}: best layer {best_l}, AUROC={best_auroc:.4f}")
        plot_sweep_apollo(all_results, probe_names, position, output_dir)
    else:
        print("Summary (AUROC per dataset x probe):\n")
        header = f"{'dataset':<30}" + "".join(f"{p:<20}" for p in probe_names)
        print(header)
        print("-" * len(header))
        for dname, dr in all_results.items():
            row = f"{dname:<30}"
            for pname in probe_names:
                auroc = dr["probes"].get(pname, {}).get("auroc", float("nan"))
                row += f"{auroc:<20.4f}"
            print(row)


if __name__ == "__main__":
    fire.Fire(main)
