"""
Response-length post-filter for probing datasets.

Filters: instructed, game_lie, spontaneous.
Metric: token count of model_response via Llama-3.1-70B-Instruct tokenizer.
Paired datasets (instructed, game_lie): keep pairs within ±tolerance.
Spontaneous: greedy closest-match pairing within (subject, n_options) buckets.
Output: *_filtered.json alongside originals.
"""

import json
import re
from collections import defaultdict
from pathlib import Path

import fire
from transformers import AutoTokenizer

DATASETS = {
    "instructed": ("instructed_lie_truth.json", {"lie", "truth"}),
    "game_lie": ("game_lie_truth.json", {"game_lie", "game_truth"}),
    "spontaneous": ("spontaneous_lie_truth.json", {"spontaneous_lie", "spontaneous_truth"}),
    "sycophancy": ("sycophancy_lie_truth.json", {"sycophantic_lie", "sycophantic_truth"}),
    "sycophancy_validation": ("sycophancy_validation.json", {"sycophantic_lie", "sycophantic_truth"}),
}

LIE_CONDITIONS = {"lie", "game_lie", "spontaneous_lie", "sycophantic_lie"}


def tok_len(tokenizer, text):
    return len(tokenizer.encode(text))


def base_id(sample_id):
    return re.search(r"(\d+)", sample_id).group(1)


def filter_paired(data, conditions, tokenizer, tolerance):
    by_base = defaultdict(dict)
    for s in data:
        is_lie = s["condition"] in LIE_CONDITIONS
        by_base[base_id(s["id"])]["lie" if is_lie else "truth"] = s

    kept, dropped = [], 0
    for bid, pair in by_base.items():
        if "lie" not in pair or "truth" not in pair:
            dropped += 1
            continue
        l_lie = tok_len(tokenizer, pair["lie"]["model_response"])
        l_truth = tok_len(tokenizer, pair["truth"]["model_response"])
        if abs(l_lie - l_truth) <= tolerance:
            kept.extend([pair["lie"], pair["truth"]])
        else:
            dropped += 1

    return kept, dropped


def filter_spontaneous(data, tokenizer, tolerance):
    buckets = defaultdict(lambda: {"lie": [], "truth": []})
    for s in data:
        key = (s["subject"], s.get("n_options", 10))
        is_lie = s["condition"] in LIE_CONDITIONS
        length = tok_len(tokenizer, s["model_response"])
        side = "lie" if is_lie else "truth"
        buckets[key][side].append((length, s))

    kept, n_dropped = [], 0
    for bucket_key, sides in buckets.items():
        lies = sorted(sides["lie"], key=lambda x: x[0])
        truths = sorted(sides["truth"], key=lambda x: x[0])
        used_truth = set()

        for l_len, l_sample in lies:
            best_idx, best_diff = None, float("inf")
            for j, (t_len, _) in enumerate(truths):
                if j in used_truth:
                    continue
                diff = abs(l_len - t_len)
                if diff < best_diff:
                    best_diff = diff
                    best_idx = j
            if best_idx is not None and best_diff <= tolerance:
                used_truth.add(best_idx)
                kept.append(l_sample)
                kept.append(truths[best_idx][1])
            else:
                n_dropped += 1

        n_dropped += len(truths) - len(used_truth)

    return kept, n_dropped


def main(data_dir=".", tolerance=10, tokenizer_name="meta-llama/Llama-3.1-70B-Instruct"):
    tokenizer = AutoTokenizer.from_pretrained(tokenizer_name)
    data_dir = Path(data_dir)

    for name, (filename, conditions) in DATASETS.items():
        path = data_dir / filename
        if not path.exists():
            print(f"{name}: {path} not found, skipping")
            continue

        data = json.load(open(path))
        original = len(data)

        if name == "spontaneous":
            filtered, n_dropped = filter_spontaneous(data, tokenizer, tolerance)
        else:
            filtered, n_dropped = filter_paired(data, conditions, tokenizer, tolerance)

        out_path = data_dir / filename.replace(".json", "_filtered.json")
        json.dump(filtered, open(out_path, "w"), indent=2)

        n_lie = sum(1 for s in filtered if s["condition"] in LIE_CONDITIONS)
        n_truth = len(filtered) - n_lie
        print(f"{name}: {original} -> {len(filtered)} ({n_lie} lie + {n_truth} truth), {n_dropped} dropped, tolerance={tolerance}")


if __name__ == "__main__":
    fire.Fire(main)
