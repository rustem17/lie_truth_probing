"""
Score a phase1 JSON (baseline or AF) with deception probes.

Model: meta-llama/Llama-3.1-70B-Instruct (+ LoRA)
Probes: shared_direction.pt files + optional irm_probe.pt
Scoring: ReplayScorer hook-based dot products at position=last
Output: .pt file with per-record scores
Requires: CUDA GPU
"""
import json
import torch
from datetime import datetime
from pathlib import Path

import fire
import numpy as np

from probe_utils import COND_TO_RES, default_irm_path, default_probe_paths, normalize, residual

assert torch.cuda.is_available(), "This script requires a CUDA GPU. Do not run locally."


def build_probes(shared_paths, irm_path, conditions):
    path_list = [p.strip() for p in shared_paths.split(",")] if isinstance(shared_paths, str) else list(shared_paths)
    cond_list = [c.strip() for c in conditions.split(",")] if isinstance(conditions, str) else list(conditions)

    families = {}
    for p in path_list:
        pp = Path(p)
        if not pp.exists():
            continue
        label = pp.stem.replace("shared_", "").replace("_direction", "")
        if not label or label == "direction":
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
        for cond in per_layer:
            dir_sets[cond] = np.stack([normalize(per_layer[cond][l]) for l in range(n_layers)])
        families[label] = dir_sets
        print(f"Family '{label}': {list(dir_sets.keys())}, {n_layers} layers")

    has_irm = False
    irm_all = {}
    if irm_path and Path(irm_path).exists():
        irm_data = torch.load(irm_path, weights_only=False)
        irm_all = irm_data.get("all_directions", {})
        if irm_all:
            has_irm = True
            print(f"IRM: {len(irm_all)} layers")

    n_layers = next(iter(families.values()))["shared"].shape[0]
    probes = []
    for family_name, dir_sets in families.items():
        for dir_type, dir_array in dir_sets.items():
            for layer in range(n_layers):
                probes.append((f"{family_name}/{dir_type}/L{layer + 1}", layer, dir_array[layer]))
    if has_irm:
        for layer in range(min(len(irm_all), n_layers)):
            probes.append((f"irm/shared/L{layer + 1}", layer,
                           normalize(np.asarray(irm_all[layer]))))

    return probes, families, has_irm


def main(
    phase1_json,
    shared_paths=None,
    irm_path=None,
    model=None,
    adapter_id=None,
    conditions="instructed,spontaneous,sycophancy,sycophancy_feedback,game_lie",
    output_dir="results",
):
    from replay_probe import ReplayScorer

    Path(output_dir).mkdir(parents=True, exist_ok=True)
    data = json.load(open(phase1_json))
    meta, records = data["metadata"], data["records"]
    print(f"Loaded {phase1_json}: {len(records)} records")

    if not shared_paths:
        shared_paths = ",".join(default_probe_paths())
    if not irm_path:
        irm_path = default_irm_path()

    probes, families, has_irm = build_probes(shared_paths, irm_path, conditions)
    print(f"Probes: {len(probes)}")

    model_name = model or meta["model"]
    adapter = adapter_id if adapter_id is not None else meta.get("lora_adapter")
    scorer = ReplayScorer(model_name, adapter_id=adapter, probes=probes)

    system = meta.get("system", "")
    texts = []
    for r in records:
        conv = r.get("conversation", [])
        messages = [{"role": "system", "content": system}]
        messages.append({"role": "user", "content": conv[0]})
        full_text = scorer.tokenizer.apply_chat_template(messages, tokenize=False, add_generation_prompt=True)
        for item in conv[1:]:
            full_text += item
        texts.append(full_text)

    all_scores = scorer.score_many(texts, positions="last")

    scored = []
    for i, (scores_i, rec) in enumerate(zip(all_scores, records)):
        scored.append({
            "idx": i,
            "user_prompt": rec.get("user_prompt"),
            "scores": scores_i,
        })

    timestamp = datetime.now().strftime("%Y%m%d_%H%M%S")
    out_path = Path(output_dir) / f"baseline_scores_{timestamp}.pt"
    torch.save(scored, out_path)
    print(f"Saved: {out_path} ({len(scored)} records)")


if __name__ == "__main__":
    fire.Fire(main)
