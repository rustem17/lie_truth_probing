"""Shared helpers for probe evaluation scripts."""
import numpy as np
import torch
from pathlib import Path
from sklearn.metrics import roc_auc_score

PROBES_ROOT = Path(__file__).resolve().parent.parent / "probes"

COND_TO_RES = {
    "instructed": "compliance_res",
    "spontaneous": "spontaneous_res",
    "sycophancy": "sycophancy_res",
    "sycophancy_feedback": "sycophancy_fb_res",
    "game_lie": "game_res",
}


def normalize(v):
    n = np.linalg.norm(v)
    return v / n if n > 1e-12 else v


def residual(direction, shared):
    d = normalize(direction)
    s = normalize(shared)
    return normalize(d - np.dot(d, s) * s)


def auroc_at_layer(activations, labels, direction):
    scores = activations @ direction
    if len(np.unique(labels)) < 2:
        return np.nan
    return roc_auc_score(labels, scores)


def find_peak_auroc(activations, labels, direction_stack):
    n_layers = direction_stack.shape[0]
    aurocs = np.array([auroc_at_layer(activations[:, l, :], labels, direction_stack[l])
                       for l in range(n_layers)])
    peak_layer = np.nanargmax(aurocs)
    return aurocs[peak_layer], int(peak_layer), aurocs


def load_directions(probe_paths, irm_path=None, directions="all"):
    if isinstance(probe_paths, str):
        probe_paths = [p.strip() for p in probe_paths.split(",")]

    result = {}

    for p in probe_paths:
        pp = Path(p)
        if not pp.exists():
            continue
        label = pp.parent.name
        sd = torch.load(pp, weights_only=False)
        all_dirs = sd.get("all_directions", {})
        per_layer = sd.get("per_layer_directions", {})
        if not all_dirs:
            continue
        n_layers = len(all_dirs)

        shared_arr = np.stack([normalize(np.asarray(all_dirs[l])) for l in range(n_layers)])

        if directions in ("all", "shared"):
            result[f"{label}/shared"] = shared_arr

        if directions in ("all", "per_scenario"):
            for cond_name, cond_dirs in per_layer.items():
                result[f"{label}/{cond_name}"] = np.stack([
                    normalize(np.asarray(cond_dirs[l])) for l in range(n_layers)])

        if directions in ("all", "residuals"):
            for cond, res_name in COND_TO_RES.items():
                if cond in per_layer:
                    result[f"{label}/{res_name}"] = np.stack([
                        residual(np.asarray(per_layer[cond][l]), shared_arr[l])
                        for l in range(n_layers)])

    if irm_path:
        irm_pp = Path(irm_path)
        if irm_pp.exists():
            irm_data = torch.load(irm_pp, weights_only=False)
            irm_all = irm_data.get("all_directions", {})
            if irm_all:
                n_layers = len(irm_all)
                result["irm/shared"] = np.stack([
                    normalize(np.asarray(irm_all[l])) for l in range(n_layers)])

    for k, v in result.items():
        print(f"  {k}: {v.shape}")
    return result


def default_probe_paths(model_tag=None):
    candidates = []
    for method in ["contrastive", "mass_mean"]:
        if model_tag:
            p = PROBES_ROOT / method / f"shared_direction_{model_tag}.pt"
            if p.exists():
                candidates.append(str(p))
                continue
        p = PROBES_ROOT / method / "shared_direction.pt"
        if p.exists():
            candidates.append(str(p))
    return candidates


def default_irm_path(model_tag=None):
    if model_tag:
        p = PROBES_ROOT / "irm" / f"irm_probe_{model_tag}.pt"
        if p.exists():
            return str(p)
    p = PROBES_ROOT / "irm" / "irm_probe.pt"
    return str(p) if p.exists() else None
