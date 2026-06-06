import argparse
import os
from pathlib import Path

import torch
from datasets import load_dataset

# This project fine-tunes text-only Llama models. Some local environments have
# incompatible torch/torchvision builds, and optional vision imports can crash
# before training starts. Disable that optional path before PEFT imports models.
import transformers.utils.import_utils as transformers_import_utils
import transformers.utils as transformers_utils

transformers_import_utils.is_torchvision_available = lambda: False
transformers_utils.is_torchvision_available = lambda: False

_read_text = Path.read_text


def _read_text_utf8(self, encoding=None, errors=None, newline=None):
    return _read_text(
        self,
        encoding=encoding or "utf-8",
        errors=errors,
    )


Path.read_text = _read_text_utf8

from peft import LoraConfig, prepare_model_for_kbit_training
from transformers import AutoModelForCausalLM, AutoTokenizer, BitsAndBytesConfig
from trl import SFTConfig, SFTTrainer


def format_example(example, tokenizer):
    return tokenizer.apply_chat_template(
        example["messages"],
        tokenize=False,
        add_generation_prompt=False,
    )


def main():
    parser = argparse.ArgumentParser(
        description="Fine-tune a Llama instruct model with LoRA on lab explanations."
    )
    parser.add_argument("--model-id", default="meta-llama/Llama-3.1-8B-Instruct")
    parser.add_argument("--train-file", default="data/finetune_llama/train.jsonl")
    parser.add_argument("--validation-file", default="data/finetune_llama/validation.jsonl")
    parser.add_argument("--output-dir", default="outputs/llama-lab-lora")
    parser.add_argument("--max-seq-length", type=int, default=4096)
    parser.add_argument("--epochs", type=float, default=2)
    parser.add_argument("--learning-rate", type=float, default=2e-4)
    parser.add_argument("--batch-size", type=int, default=1)
    parser.add_argument("--grad-accum", type=int, default=8)
    parser.add_argument("--save-steps", type=int, default=100)
    parser.add_argument("--eval-steps", type=int, default=100)
    parser.add_argument(
        "--no-4bit",
        action="store_true",
        help="Disable 4-bit QLoRA. This usually requires a much larger GPU.",
    )
    args = parser.parse_args()

    token = (os.getenv("HF_TOKEN") or "").strip()
    if not token:
        raise EnvironmentError(
            "Set HF_TOKEN before loading Llama weights from Hugging Face."
        )

    dataset = load_dataset(
        "json",
        data_files={
            "train": args.train_file,
            "validation": args.validation_file,
        },
    )

    tokenizer = AutoTokenizer.from_pretrained(args.model_id, token=token)
    if tokenizer.pad_token is None:
        tokenizer.pad_token = tokenizer.eos_token
    tokenizer.padding_side = "right"

    use_4bit = not args.no_4bit
    supports_bf16 = torch.cuda.is_available() and torch.cuda.is_bf16_supported()
    compute_dtype = torch.bfloat16 if supports_bf16 else torch.float16
    quantization_config = None

    if use_4bit:
        if not torch.cuda.is_available():
            raise RuntimeError("4-bit QLoRA training requires a CUDA GPU.")
        quantization_config = BitsAndBytesConfig(
            load_in_4bit=True,
            bnb_4bit_quant_type="nf4",
            bnb_4bit_use_double_quant=True,
            bnb_4bit_compute_dtype=compute_dtype,
        )

    model = AutoModelForCausalLM.from_pretrained(
        args.model_id,
        token=token,
        dtype=compute_dtype if torch.cuda.is_available() else torch.float32,
        quantization_config=quantization_config,
        device_map={"": 0} if use_4bit else "auto",
    )
    if use_4bit:
        model = prepare_model_for_kbit_training(
            model,
            use_gradient_checkpointing=True,
        )
    model.config.use_cache = False

    peft_config = LoraConfig(
        r=16,
        lora_alpha=32,
        lora_dropout=0.05,
        bias="none",
        task_type="CAUSAL_LM",
        target_modules=[
            "q_proj",
            "k_proj",
            "v_proj",
            "o_proj",
            "gate_proj",
            "up_proj",
            "down_proj",
        ],
    )

    training_args = SFTConfig(
        output_dir=args.output_dir,
        num_train_epochs=args.epochs,
        learning_rate=args.learning_rate,
        per_device_train_batch_size=args.batch_size,
        per_device_eval_batch_size=args.batch_size,
        gradient_accumulation_steps=args.grad_accum,
        gradient_checkpointing=True,
        max_length=args.max_seq_length,
        packing=False,
        logging_steps=10,
        save_steps=args.save_steps,
        eval_steps=args.eval_steps,
        eval_strategy="steps",
        save_total_limit=2,
        bf16=supports_bf16,
        fp16=torch.cuda.is_available() and not supports_bf16,
        report_to="none",
    )

    trainer = SFTTrainer(
        model=model,
        args=training_args,
        train_dataset=dataset["train"],
        eval_dataset=dataset["validation"],
        peft_config=peft_config,
        formatting_func=lambda example: format_example(example, tokenizer),
        processing_class=tokenizer,
    )

    trainer.train()
    trainer.save_model(args.output_dir)
    tokenizer.save_pretrained(args.output_dir)
    print(f"Saved Llama LoRA adapter to: {args.output_dir}")


if __name__ == "__main__":
    main()
