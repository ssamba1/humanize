"""Shared base-model loader — full precision (string passthrough) or 4-bit QLoRA.

4-bit (QLoRA) lets a 3B model train on a free 16GB T4 (Colab/Kaggle). When off, returns the model id
string so trl loads it itself (and this module needs no GPU/torch — testable)."""

from __future__ import annotations


def load_model(model_id: str, load_4bit: bool = False):
    if not load_4bit:
        return model_id  # trl/transformers loads the string itself

    import torch
    from peft import prepare_model_for_kbit_training
    from transformers import AutoModelForCausalLM, BitsAndBytesConfig

    bnb = BitsAndBytesConfig(
        load_in_4bit=True,
        bnb_4bit_quant_type="nf4",
        bnb_4bit_compute_dtype=torch.bfloat16,
        bnb_4bit_use_double_quant=True,
    )
    model = AutoModelForCausalLM.from_pretrained(model_id, quantization_config=bnb, device_map="auto")
    return prepare_model_for_kbit_training(model)
