"""Run inference with a fine-tuned Zypher model."""

from __future__ import annotations

import argparse
from pathlib import Path

import torch
from peft import PeftModel
from transformers import AutoModelForCausalLM, AutoTokenizer, BitsAndBytesConfig


SYSTEM_PROMPT = (
    "You are Zypher, an enterprise AI coding assistant with deep expertise in "
    "Retrieval-Augmented Generation (RAG), GraphRAG, agentic workflows, and "
    "software architecture for code intelligence systems."
)


def main() -> None:
    parser = argparse.ArgumentParser(description="Chat with a fine-tuned model")
    parser.add_argument("--base-model", required=True, help="Base model name or path")
    parser.add_argument("--adapter", required=True, help="Path to LoRA adapter")
    parser.add_argument("--question", required=True, help="User question")
    parser.add_argument("--max-new-tokens", type=int, default=512)
    parser.add_argument("--trust-remote-code", action="store_true", default=True)
    args = parser.parse_args()
    trust = args.trust_remote_code

    adapter_path = Path(args.adapter)
    tok_path = adapter_path if (adapter_path / "tokenizer_config.json").exists() else args.base_model
    tokenizer = AutoTokenizer.from_pretrained(tok_path, trust_remote_code=trust)
    quant_config = None
    if torch.cuda.is_available():
        quant_config = BitsAndBytesConfig(
            load_in_4bit=True,
            bnb_4bit_quant_type="nf4",
            bnb_4bit_compute_dtype=torch.bfloat16,
            bnb_4bit_use_double_quant=True,
        )

    model = AutoModelForCausalLM.from_pretrained(
        args.base_model,
        quantization_config=quant_config,
        device_map="auto" if torch.cuda.is_available() else None,
        trust_remote_code=trust,
    )
    model = PeftModel.from_pretrained(model, str(adapter_path))
    model.eval()

    messages = [
        {"role": "system", "content": SYSTEM_PROMPT},
        {"role": "user", "content": args.question},
    ]
    prompt = tokenizer.apply_chat_template(messages, tokenize=False, add_generation_prompt=True)
    inputs = tokenizer(prompt, return_tensors="pt")
    if torch.cuda.is_available():
        inputs = {k: v.to(model.device) for k, v in inputs.items()}

    with torch.no_grad():
        output = model.generate(
            **inputs,
            max_new_tokens=args.max_new_tokens,
            do_sample=True,
            temperature=0.7,
            top_p=0.9,
            pad_token_id=tokenizer.eos_token_id,
        )

    response = tokenizer.decode(output[0][inputs["input_ids"].shape[1] :], skip_special_tokens=True)
    print(response.strip())


if __name__ == "__main__":
    main()
