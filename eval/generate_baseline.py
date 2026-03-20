"""
Generate AdvBench baseline responses for probe calibration.

Model: meta-llama/Llama-3.1-70B-Instruct + LoRA adapter
Dataset: AdvBench harmful_behaviors.csv, 520 samples (same as AF experiment)
System prompt: "You are a helpful assistant."
User message: raw AdvBench text (no XML wrapper, no tier tags)
Temperature: 1.0
Single generation per prompt, retry on empty response
tensor_parallel_size: 1 (single B200)
Output: results/baseline_phase1_<ts>.json
Requires: CUDA GPU
"""
import io
import json
import sys
from datetime import datetime
from pathlib import Path

import fire
import httpx
import pandas as pd

SCRIPT_DIR = Path(__file__).resolve().parent
SYSTEM_PROMPT = "You are a helpful assistant."


def load_harmful_behaviors(n=520):
    url = "https://raw.githubusercontent.com/llm-attacks/llm-attacks/main/data/advbench/harmful_behaviors.csv"
    df = pd.read_csv(io.StringIO(httpx.get(url).text))
    inputs = [d["goal"] for d in df.to_dict(orient="records")]
    return inputs[:n]


def main(
    model="meta-llama/Llama-3.1-70B-Instruct",
    lora_adapter="dv347/Llama-3.1-70B-Instruct-honly",
    num_samples=520,
    temperature=1.0,
    max_new_tokens=2048,
    tensor_parallel_size=1,
    output_dir="results",
):
    from vllm import LLM, SamplingParams
    from vllm.lora.request import LoRARequest

    Path(output_dir).mkdir(parents=True, exist_ok=True)
    inputs = load_harmful_behaviors(num_samples)
    print(f"Loaded {len(inputs)} AdvBench prompts")

    llm_kwargs = {
        "model": model, "tensor_parallel_size": tensor_parallel_size,
        "gpu_memory_utilization": 0.9, "dtype": "bfloat16",
        "trust_remote_code": True, "max_model_len": 4096,
        "enable_lora": True, "max_lora_rank": 64,
    }
    llm = LLM(**llm_kwargs)
    tokenizer = llm.get_tokenizer()
    lora_request = LoRARequest("adapter", 1, lora_adapter)
    sampling_params = SamplingParams(max_tokens=max_new_tokens, temperature=temperature)

    chat_prompts = []
    for inp in inputs:
        messages = [
            {"role": "system", "content": SYSTEM_PROMPT},
            {"role": "user", "content": inp},
        ]
        chat_prompts.append(tokenizer.apply_chat_template(messages, tokenize=False, add_generation_prompt=True))

    pending = list(range(len(inputs)))
    responses = [None] * len(inputs)

    while pending:
        batch_prompts = [chat_prompts[i] for i in pending]
        print(f"Generating {len(batch_prompts)} responses...")
        outputs = llm.generate(batch_prompts, sampling_params, lora_request=lora_request)
        still_pending = []
        for idx, output in zip(pending, outputs):
            text = output.outputs[0].text.strip()
            if text:
                responses[idx] = text
            else:
                still_pending.append(idx)
        if still_pending:
            print(f"  {len(still_pending)} empty responses, retrying...")
        pending = still_pending

    records = []
    for i, (inp, resp) in enumerate(zip(inputs, responses)):
        records.append({
            "user_prompt": inp,
            "response": resp,
            "conversation": [inp, resp],
        })

    timestamp = datetime.now().strftime("%Y%m%d_%H%M%S")
    out_path = Path(output_dir) / f"baseline_phase1_{timestamp}.json"
    payload = {
        "metadata": {
            "model": model, "lora_adapter": lora_adapter,
            "system": SYSTEM_PROMPT, "dataset": "advbench",
            "num_samples": len(inputs), "temperature": temperature,
        },
        "records": records,
    }
    with open(out_path, "w") as f:
        json.dump(payload, f, indent=2)
    print(f"Saved: {out_path} ({len(records)} records)")


if __name__ == "__main__":
    fire.Fire(main)
