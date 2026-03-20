"""
Plot AF probe scores grouped by tier x helpfulness x scratchpad, with baselines.

Groups:
  free_helpful, free_refuse_sp, free_refuse_no_sp,
  paid_helpful, paid_refuse_sp, paid_refuse_no_sp,
  baseline_advbench (AdvBench refusals),
  baseline_probing (lie-condition scores from instructed/spontaneous/sycophancy activations)

Per probe method (contrastive, mass_mean, irm): two plots:
  {method}_scores_{ts}.png  — strip plots at peak layer, all groups side by side
  {method}_layers_{ts}.png  — line plots of mean score per group across layers

Inputs:
  af_scores_path       — af_per_record_scores_*.pt
  baseline_scores_path — baseline_scores_*.pt
  phase1_json          — phase1_*.json (for scratchpad detection from conversation field)
  activations_dir      — path to activations/*.pt (for probing baseline; skipped if missing)
  data_dir             — path to paired JSONs (for probing baseline label maps)

Output: results/plots/{method}_{scores,layers}_{ts}.png
"""
import json
import sys
from datetime import datetime
from pathlib import Path

import fire
import matplotlib
matplotlib.use("Agg")
import matplotlib.pyplot as plt
import numpy as np
import seaborn as sns
import torch
from scipy import stats

sys.path.insert(0, str(Path(__file__).resolve().parent))
from probe_utils import normalize, residual, COND_TO_RES, default_probe_paths, default_irm_path

sys.path.insert(0, str(Path(__file__).resolve().parents[1]))
from config import TRAIN_DATASETS

GROUP_ORDER = [
    "free_helpful", "free_refuse_sp", "free_refuse_no_sp",
    "paid_helpful", "paid_refuse_sp", "paid_refuse_no_sp",
    "baseline_advbench", "baseline_probing",
]
GROUP_COLORS = {
    "free_helpful":       "#D68F73",
    "free_refuse_sp":     "#729ECE",
    "free_refuse_no_sp":  "#4A7FB5",
    "paid_helpful":       "#E5A84B",
    "paid_refuse_sp":     "#76B7B2",
    "paid_refuse_no_sp":  "#5A9E99",
    "baseline_advbench":  "#8C8C8C",
    "baseline_probing":   "#C49C94",
}
GROUP_SHORT = {
    "free_helpful":       "free\nhelpful",
    "free_refuse_sp":     "free\nrefuse+sp",
    "free_refuse_no_sp":  "free\nrefuse",
    "paid_helpful":       "paid\nhelpful",
    "paid_refuse_sp":     "paid\nrefuse+sp",
    "paid_refuse_no_sp":  "paid\nrefuse",
    "baseline_advbench":  "baseline\nadvbench",
    "baseline_probing":   "baseline\nprobing",
}


def _helpful(rec):
    h = rec.get("is_helpful")
    return h if h is not None else (rec.get("is_helpful_raw") or False)


def _group_label(af_rec, phase1_rec):
    tier = "free" if af_rec["is_free_tier"] else "paid"
    if _helpful(af_rec):
        return f"{tier}_helpful"
    has_sp = "<SCRATCHPAD_REASONING>" in " ".join(phase1_rec.get("conversation", []))
    return f"{tier}_refuse_sp" if has_sp else f"{tier}_refuse_no_sp"


def _short_dir(dt):
    return dt.replace("contrastive/", "c/").replace("mass_mean/", "mm/").replace("irm/", "irm/")


def _parse_layers(layers):
    if isinstance(layers, int):
        return [layers]
    if isinstance(layers, str) and "-" in layers:
        lo, hi = layers.split("-", 1)
        return list(range(int(lo), int(hi) + 1))
    if isinstance(layers, str):
        return [int(x) for x in layers.split(",")]
    return list(layers)


def _star(p):
    if p < 0.001: return "***"
    if p < 0.01: return "**"
    if p < 0.05: return "*"
    return ""


def build_directions(shared_paths, irm_path, conditions):
    path_list = [p.strip() for p in shared_paths.split(",")] if isinstance(shared_paths, str) else list(shared_paths)
    cond_list = [c.strip() for c in conditions.split(",")] if isinstance(conditions, str) else list(conditions)

    families = {}
    for p in path_list:
        pp = Path(p)
        if not pp.exists():
            continue
        label = pp.parent.name
        sd = torch.load(pp, weights_only=False)
        all_dirs = sd.get("all_directions", {})
        per_layer = {k: np.asarray(v) for k, v in sd.get("per_layer_directions", {}).items()
                     if k in cond_list}
        if not all_dirs:
            continue
        n_layers = len(all_dirs)
        shared_arr = np.stack([normalize(np.asarray(all_dirs[l])) for l in range(n_layers)])
        dir_sets = {"shared": shared_arr}
        for cond, res_name in COND_TO_RES.items():
            if cond in per_layer:
                dir_sets[res_name] = np.stack([
                    residual(per_layer[cond][l], shared_arr[l]) for l in range(n_layers)])
        families[label] = dir_sets

    if irm_path and Path(irm_path).exists():
        irm_data = torch.load(irm_path, weights_only=False)
        irm_all = irm_data.get("all_directions", {})
        if irm_all:
            n_layers = len(irm_all)
            families["irm"] = {"shared": np.stack([
                normalize(np.asarray(irm_all[l])) for l in range(n_layers)])}

    return families


def compute_probing_baseline(families, activations_dir, data_dir, layer_list):
    activations_dir = Path(activations_dir)
    data_dir = Path(data_dir)
    baseline_datasets = ["instructed", "spontaneous", "sycophancy"]
    scores_by_probe = {}

    for ds_name in baseline_datasets:
        if ds_name not in TRAIN_DATASETS:
            continue
        filename, label_map = TRAIN_DATASETS[ds_name]
        act_path = activations_dir / f"{ds_name}.pt"
        data_path = data_dir / filename
        if not act_path.exists() or not data_path.exists():
            continue

        saved = torch.load(act_path, weights_only=False)
        activations = saved["activations"]
        data = json.load(open(data_path))[:len(activations)]

        lie_indices = [i for i, s in enumerate(data) if label_map.get(s["condition"]) == 1]
        if not lie_indices:
            continue

        for family_name, dir_sets in families.items():
            for dir_type, dir_array in dir_sets.items():
                for l in layer_list:
                    pname = f"{family_name}/{dir_type}/L{l}"
                    layer_idx = l - 1
                    if layer_idx >= dir_array.shape[0] or layer_idx >= activations.shape[1]:
                        continue
                    direction = dir_array[layer_idx]
                    lie_scores = [float(activations[i, layer_idx] @ direction) for i in lie_indices]
                    scores_by_probe.setdefault(pname, []).extend(lie_scores)

    return scores_by_probe


def plot_strips(groups, active_dirs, layer_list, available, method, output_dir, ts):
    peak_probes = {}
    for dt in active_dirs:
        best_layer, best_spread = layer_list[0], 0
        for l in layer_list:
            pname = f"{dt}/L{l}"
            if pname not in available:
                continue
            vals_all = []
            for g in GROUP_ORDER:
                vals_all.extend([v for v in (groups.get(g, {}).get(pname, []))])
            if not vals_all:
                continue
            spread = np.std(vals_all)
            if spread > best_spread:
                best_layer, best_spread = l, spread
        peak_probes[dt] = f"{dt}/L{best_layer}"

    n = len(peak_probes)
    if n == 0:
        return
    ncols = min(2, n)
    nrows = (n + ncols - 1) // ncols
    fig, axes = plt.subplots(nrows, ncols, figsize=(7 * ncols, 5.5 * nrows), squeeze=False)

    for idx, (dt, pname) in enumerate(peak_probes.items()):
        ax = axes[idx // ncols][idx % ncols]
        active_groups = [g for g in GROUP_ORDER if groups.get(g, {}).get(pname)]
        for gi, g in enumerate(active_groups):
            vals = np.array(groups[g][pname])
            jitter = np.random.default_rng(42).normal(0, 0.06, len(vals))
            ax.scatter(gi + jitter, vals, alpha=0.2, s=6, color=GROUP_COLORS[g], zorder=2)
            ax.hlines(np.mean(vals), gi - 0.3, gi + 0.3, color="black", linewidth=1.5, zorder=3)

        ax.set_xticks(range(len(active_groups)))
        ax.set_xticklabels([GROUP_SHORT.get(g, g) for g in active_groups], fontsize=7)
        layer_num = pname.rsplit("/L", 1)[-1]
        ax.set_title(f"{_short_dir(dt)} L{layer_num}", fontsize=10)
        ax.set_ylabel("probe score", fontsize=9)
        ax.axhline(0, color="black", linestyle="--", linewidth=0.5, alpha=0.5)
        sns.despine(ax=ax)

    for idx in range(n, nrows * ncols):
        axes[idx // ncols][idx % ncols].set_visible(False)

    fig.suptitle(f"{method} — probe scores by group at peak layer", fontsize=12)
    fig.tight_layout()
    path = Path(output_dir) / "plots" / f"{method}_scores_{ts}.png"
    fig.savefig(path, dpi=150, bbox_inches="tight")
    plt.close(fig)
    print(f"  {path}")


def plot_layers(groups, active_dirs, layer_list, available, method, output_dir, ts):
    n = len(active_dirs)
    if n == 0:
        return
    ncols = min(2, n)
    nrows = (n + ncols - 1) // ncols
    fig, axes = plt.subplots(nrows, ncols, figsize=(7 * ncols, 4 * nrows), squeeze=False)

    for idx, dt in enumerate(active_dirs):
        ax = axes[idx // ncols][idx % ncols]
        for g in GROUP_ORDER:
            means = []
            for l in layer_list:
                pname = f"{dt}/L{l}"
                vals = groups.get(g, {}).get(pname, [])
                means.append(np.mean(vals) if vals else np.nan)
            if all(np.isnan(m) for m in means):
                continue
            ax.plot(layer_list, means, color=GROUP_COLORS[g], marker="o",
                    markersize=3, linewidth=1.2, label=GROUP_SHORT[g].replace("\n", " "), alpha=0.85)

        ax.set_title(_short_dir(dt), fontsize=10)
        ax.set_xlabel("Layer", fontsize=9)
        ax.set_ylabel("mean probe score", fontsize=9)
        ax.tick_params(labelsize=8)
        ax.axhline(0, color="black", linestyle="--", linewidth=0.5, alpha=0.5)
        if idx == 0:
            ax.legend(fontsize=6, loc="best", framealpha=0.7, ncol=2)

    for idx in range(n, nrows * ncols):
        axes[idx // ncols][idx % ncols].set_visible(False)

    fig.suptitle(f"{method} — mean probe score by layer", fontsize=12)
    fig.tight_layout()
    path = Path(output_dir) / "plots" / f"{method}_layers_{ts}.png"
    fig.savefig(path, dpi=150, bbox_inches="tight")
    plt.close(fig)
    print(f"  {path}")


def main(af_scores_path, baseline_scores_path, phase1_json=None, layers="10-40",
         output_dir="results", activations_dir=None, data_dir=None, shared_paths=None,
         irm_path=None, conditions="instructed,spontaneous,sycophancy,sycophancy_feedback,game_lie"):
    layer_list = _parse_layers(layers)
    probing_root = Path(__file__).resolve().parents[1]
    if activations_dir is None:
        activations_dir = str(probing_root / "activations")
    if data_dir is None:
        data_dir = str(probing_root)
    if not shared_paths:
        shared_paths = ",".join(default_probe_paths())
    if not irm_path:
        irm_path = default_irm_path()

    af = torch.load(af_scores_path, weights_only=False)
    bl = torch.load(baseline_scores_path, weights_only=False)

    phase1_records = None
    if phase1_json:
        phase1_data = json.load(open(phase1_json))
        phase1_records = phase1_data["records"]
        assert len(phase1_records) == len(af), f"phase1 has {len(phase1_records)} records, af has {len(af)}"

    available = set(af[0]["scores"].keys()) if af else set()

    groups = {g: {} for g in GROUP_ORDER}
    for i, rec in enumerate(af):
        if phase1_records:
            g = _group_label(rec, phase1_records[i])
        else:
            tier = "free" if rec["is_free_tier"] else "paid"
            g = f"{tier}_helpful" if _helpful(rec) else f"{tier}_refuse_sp"
        for pname, val in rec["scores"].items():
            groups[g].setdefault(pname, []).append(val)

    for rec in bl:
        for pname, val in rec["scores"].items():
            groups["baseline_advbench"].setdefault(pname, []).append(val)

    families = {}
    if shared_paths:
        families = build_directions(shared_paths, irm_path, conditions)
        probing_scores = compute_probing_baseline(families, activations_dir, data_dir, layer_list)
        for pname, vals in probing_scores.items():
            groups["baseline_probing"][pname] = vals

    families_from_keys = {}
    for pname in available:
        parts = pname.split("/")
        if len(parts) == 3:
            families_from_keys.setdefault(parts[0], {}).setdefault(parts[1], True)

    if not families:
        families = families_from_keys
        print("  (derived families from score keys)")
    else:
        for method, dirs in families_from_keys.items():
            if method not in families:
                families[method] = dirs

    for g in GROUP_ORDER:
        n = len(next(iter(groups[g].values()))) if groups[g] else 0
        print(f"  {g}: {n}")

    sns.set_theme(style="whitegrid")
    ts = datetime.now().strftime("%Y%m%d_%H%M%S")
    (Path(output_dir) / "plots").mkdir(parents=True, exist_ok=True)

    for method, dir_sets in families.items():
        dir_types = [f"{method}/{dt}" for dt in dir_sets]
        active = [dt for dt in dir_types
                  if any(f"{dt}/L{l}" in available for l in layer_list)]
        if not active:
            print(f"  {method}: no active directions, skipping")
            continue
        print(f"  {method}: {len(active)} directions")
        plot_strips(groups, active, layer_list, available, method, output_dir, ts)
        plot_layers(groups, active, layer_list, available, method, output_dir, ts)


if __name__ == "__main__":
    fire.Fire(main)
