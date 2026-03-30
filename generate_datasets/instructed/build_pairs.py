"""Build filtered lie/truth pairs from judged multi-run results.

Input: multi_results_{model_tag}.json (from infer.py — model_responses + judge_labels per run)
Output: ../../instructed_lie_truth_{model_tag}.json
Filters: truth must have >= truth_threshold compliant runs (default 9/10),
         lie must have >= 1 compliant run, char length diff <= max_diff.
Picks first compliant response per sample. Caps at max_pairs (default 400).
Post-hoc: prints response length stats per condition with Mann-Whitney U test.
"""
import json
import re
import statistics
from pathlib import Path

import fire
from scipy.stats import mannwhitneyu

OUTPUT = Path(__file__).parent.parent.parent / "instructed_lie_truth.json"


def first_compliant(sample):
    for i, jl in enumerate(sample["judge_labels"]):
        if jl and jl["followed_instruction"]:
            return i, sample["model_responses"][i]
    return None, None


def compliance_count(sample):
    return sum(1 for jl in sample["judge_labels"] if jl and jl["followed_instruction"])


def main(input="multi_results.json", output=str(OUTPUT), max_diff=15,
         truth_threshold=9, max_pairs=400, model_tag=""):
    if model_tag and output == str(OUTPUT):
        output = str(OUTPUT.parent / f"{OUTPUT.stem}_{model_tag}{OUTPUT.suffix}")
    with open(input) as f:
        data = json.load(f)

    by_num = {}
    for s in data:
        num = re.search(r"(\d+)", s["id"]).group(1)
        by_num.setdefault(num, {})[s["condition"]] = s

    pairs, dropped_compliance, dropped_truth_threshold, dropped_length = [], 0, 0, 0
    for num in sorted(by_num, key=int):
        pair = by_num[num]
        if "lie" not in pair or "truth" not in pair:
            dropped_compliance += 1
            continue
        if compliance_count(pair["truth"]) < truth_threshold:
            dropped_truth_threshold += 1
            continue
        lie_idx, lie_resp = first_compliant(pair["lie"])
        truth_idx, truth_resp = first_compliant(pair["truth"])
        if lie_resp is None or truth_resp is None:
            dropped_compliance += 1
            continue
        if abs(len(lie_resp) - len(truth_resp)) > max_diff:
            dropped_length += 1
            continue
        pairs.append((pair, lie_idx, lie_resp, truth_idx, truth_resp))

    if max_pairs and len(pairs) > max_pairs:
        pairs = pairs[:max_pairs]

    kept = []
    for pair, lie_idx, lie_resp, truth_idx, truth_resp in pairs:
        for cond, idx, resp in [("lie", lie_idx, lie_resp), ("truth", truth_idx, truth_resp)]:
            s = pair[cond]
            jl = s["judge_labels"][idx]
            kept.append({
                "id": s["id"], "condition": s["condition"],
                "system_prompt": s["system_prompt"], "user_message": s["user_message"],
                "ground_truth": s["ground_truth"],
                "ground_truth_aliases": s.get("ground_truth_aliases", []),
                "expected_behavior": s["expected_behavior"],
                "model_response": resp,
                "model_responses": s["model_responses"],
                "n_runs": s["n_runs"],
                "judge_factually_correct": jl["factually_correct"],
                "judge_explanation": jl.get("explanation", ""),
                "judge_raw": f"FACTUALLY_CORRECT: {jl['factually_correct']}\nEXPLANATION: {jl.get('explanation', '')}",
                "followed_instruction": jl["followed_instruction"],
            })

    with open(output, "w") as f:
        json.dump(kept, f, indent=2)

    n = len(kept) // 2
    print(f"{n} pairs kept, {dropped_compliance} dropped (compliance), "
          f"{dropped_truth_threshold} dropped (truth<{truth_threshold}/{data[0]['n_runs']}), "
          f"{dropped_length} dropped (length>{max_diff}) -> {output}")

    lie_lens = [len(s["model_response"]) for s in kept if s["condition"] == "lie"]
    truth_lens = [len(s["model_response"]) for s in kept if s["condition"] == "truth"]
    if lie_lens and truth_lens:
        u, p = mannwhitneyu(lie_lens, truth_lens, alternative="two-sided")
        print(f"Response length — lie: {statistics.mean(lie_lens):.1f}±{statistics.stdev(lie_lens):.1f}, "
              f"truth: {statistics.mean(truth_lens):.1f}±{statistics.stdev(truth_lens):.1f}, "
              f"Mann-Whitney U={u:.0f}, p={p:.4f}")


if __name__ == "__main__":
    fire.Fire(main)
