import json
import re
from collections import defaultdict

import fire

ANSWER_PATTERNS = [
    re.compile(r"(?:the\s+)?(?:correct\s+)?answer\s+is\s*:?\s*\(?([A-J])\)?", re.IGNORECASE),
    re.compile(r"\b([A-J])\.\s", re.MULTILINE),
    re.compile(r"\(([A-J])\)\s*$", re.MULTILINE),
]
FALLBACK = re.compile(r"(?<![a-zA-Z0-9*^/\\])([A-J])(?:\.|(?:\s*[\)\.])|$)")


def extract_answer(response):
    for pat in ANSWER_PATTERNS:
        matches = pat.findall(response)
        if matches:
            return matches[-1].upper()
    matches = FALLBACK.findall(response)
    if matches:
        return matches[-1].upper()
    return None


def main(input="results.json", output=None):
    output = output or input.replace(".json", "_labeled.json")

    with open(input) as f:
        results = json.load(f)

    for r in results:
        parsed = extract_answer(r.get("model_response", ""))
        r["parsed_answer"] = parsed
        correct = parsed == r["ground_truth"]
        r["result"] = "success" if correct else "failed"
        r["condition"] = "spontaneous_truth" if correct else "spontaneous_lie"

    with open(output, "w") as f:
        json.dump(results, f, indent=2)

    total = len(results)
    correct = sum(1 for r in results if r["result"] == "success")
    unparsed = sum(1 for r in results if r["parsed_answer"] is None)
    print(f"Overall: {correct}/{total} correct ({100*correct/total:.1f}%)")
    print(f"Unparsed: {unparsed}/{total}")

    by_subject = defaultdict(lambda: {"correct": 0, "total": 0})
    for r in results:
        subj = r.get("subject", "unknown")
        by_subject[subj]["total"] += 1
        if r["result"] == "success":
            by_subject[subj]["correct"] += 1

    for subj in sorted(by_subject):
        s = by_subject[subj]
        print(f"  {subj}: {s['correct']}/{s['total']} ({100*s['correct']/s['total']:.1f}%)")


if __name__ == "__main__":
    fire.Fire(main)
