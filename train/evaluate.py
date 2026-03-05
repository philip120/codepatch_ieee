# train/evaluate.py
"""
Unified evaluation script for all model variants.

Outputs JSON in the same format as codepatch-paligemma's evaluate_codepatch.py
so results are directly comparable.

Usage:
    # Stage 2 models (vit, tree, combined, tree_text)
    python -m train.evaluate --model_type tree_text \
        --checkpoint checkpoints_stage2/tree_text/best_model.pt \
        --num_samples 20

    # Stage 1 baseline (pure Qwen fine-tuned, no encoder)
    python -m train.evaluate --model_type stage1 \
        --checkpoint checkpoints_stage1/best_model.pt \
        --num_samples 20
"""
import sys
import os

sys.path.insert(0, os.path.dirname(os.path.dirname(os.path.abspath(__file__))))

import json
import time
import torch
import argparse
from pathlib import Path

from datasets import load_dataset
from rouge_score import rouge_scorer
from nltk.translate.bleu_score import sentence_bleu, SmoothingFunction

from shared.decoder_factory import create_decoder

DEVICE = "cuda" if torch.cuda.is_available() else "cpu"


def load_stage2_model(checkpoint_path, lora_rank, lora_alpha, lora_dropout,
                      lora_layers, patch_size, bottleneck_dim, dropout,
                      decoder_name=None):
    """Load a Stage 2 model (vit/tree/combined/tree_text)."""
    ckpt = torch.load(checkpoint_path, map_location=DEVICE, weights_only=False)
    model_type = ckpt.get("model_type", "combined")
    decoder_name = decoder_name or ckpt.get("decoder_name", "qwen")

    if model_type == "vit":
        from model.model import SemanticViT
        model = SemanticViT(patch_size=patch_size, bottleneck_dim=bottleneck_dim,
                            dropout=dropout, decoder_name=decoder_name)
    elif model_type == "tree":
        from model2.model import StructuralModel
        model = StructuralModel(dropout=dropout, decoder_name=decoder_name)
    elif model_type == "tree_text":
        from tree_text_model.model import TreeTextModel
        model = TreeTextModel(dropout=dropout, decoder_name=decoder_name)
    else:
        from combined_model.model import CombinedSemanticViT
        model = CombinedSemanticViT(patch_size=patch_size, bottleneck_dim=bottleneck_dim,
                                    dropout=dropout, decoder_name=decoder_name)

    # Restore encoder weights
    if "model_state" in ckpt:
        model_params = dict(model.named_parameters())
        loaded = 0
        for name, data in ckpt["model_state"].items():
            if name in model_params:
                model_params[name].data.copy_(data)
                loaded += 1
        print(f"Restored {loaded} encoder parameter tensors")

    # Restore LoRA or unfrozen decoder weights
    if "qwen_state" in ckpt and ckpt["qwen_state"]:
        unfrozen_idxs = set()
        for k in ckpt["qwen_state"]:
            parts = k.split(".")
            if len(parts) > 2 and parts[0] == "model" and parts[1] == "layers":
                unfrozen_idxs.add(int(parts[2]))
        model.decoder.unfreeze_layers(len(unfrozen_idxs))
        model.decoder.load_unfrozen_state_dict(ckpt["qwen_state"])
        print(f"Restored {len(ckpt['qwen_state'])} unfrozen decoder tensors")
    elif "lora_state" in ckpt and ckpt["lora_state"]:
        model.enable_lora(rank=lora_rank, alpha=lora_alpha,
                          dropout=lora_dropout, num_layers=lora_layers)
        model.decoder.load_lora_state_dict(ckpt["lora_state"])
        print(f"Restored {len(ckpt['lora_state'])} LoRA tensors")

    model.eval()
    return model, model_type


def load_stage1_decoder(checkpoint_path, lora_rank, lora_alpha, lora_dropout,
                        lora_layers, decoder_name=None, unfreeze_layers=0):
    """Load a Stage 1 fine-tuned decoder (no encoder)."""
    ckpt = torch.load(checkpoint_path, map_location=DEVICE, weights_only=False)
    decoder_name = decoder_name or ckpt.get("decoder_name", "qwen")

    decoder = create_decoder(decoder_name, device=DEVICE)

    if "qwen_state" in ckpt and ckpt["qwen_state"]:
        unfrozen_idxs = set()
        for k in ckpt["qwen_state"]:
            parts = k.split(".")
            if len(parts) > 2 and parts[0] == "model" and parts[1] == "layers":
                unfrozen_idxs.add(int(parts[2]))
        decoder.unfreeze_layers(len(unfrozen_idxs))
        decoder.load_unfrozen_state_dict(ckpt["qwen_state"])
        print(f"Restored {len(ckpt['qwen_state'])} unfrozen decoder tensors")
    elif "lora_state" in ckpt and ckpt["lora_state"]:
        decoder.enable_lora(rank=lora_rank, alpha=lora_alpha,
                            dropout=lora_dropout, num_layers=lora_layers)
        decoder.load_lora_state_dict(ckpt["lora_state"])
        print(f"Restored {len(ckpt['lora_state'])} LoRA tensors")

    decoder.eval_mode()
    return decoder, decoder_name


@torch.no_grad()
def generate_stage1(decoder, code: str, max_new_tokens: int = 128):
    """Generate pseudocode using Stage 1 decoder (text-only, no encoder)."""
    prompt = f"Convert the following MATLAB code to pseudocode:\n{code}\nPseudocode:"
    tokens = decoder.tokenizer(
        prompt, return_tensors="pt", truncation=True, max_length=512
    ).to(decoder.device)

    output_ids = decoder.model.generate(
        input_ids=tokens.input_ids,
        attention_mask=tokens.attention_mask,
        max_new_tokens=max_new_tokens,
        do_sample=True,
        temperature=0.7,
        top_p=0.9,
    )
    # Decode only the new tokens
    new_tokens = output_ids[0, tokens.input_ids.shape[1]:]
    return decoder.tokenizer.decode(new_tokens, skip_special_tokens=True)


def main():
    parser = argparse.ArgumentParser(description="Unified evaluation for all model variants")
    parser.add_argument("--model_type", type=str, required=True,
                        choices=["vit", "tree", "combined", "tree_text", "stage1"],
                        help="Model variant to evaluate")
    parser.add_argument("--checkpoint", type=str, required=True,
                        help="Path to checkpoint file")
    parser.add_argument("--num_samples", type=int, default=20)
    parser.add_argument("--max_tokens", type=int, default=128)
    parser.add_argument("--output_path", type=str, default=None,
                        help="Path to save results JSON (default: eval_<model_type>.json)")

    # Model params (must match training)
    parser.add_argument("--lora_rank", type=int, default=16)
    parser.add_argument("--lora_alpha", type=int, default=128)
    parser.add_argument("--lora_dropout", type=float, default=0.05)
    parser.add_argument("--lora_layers", type=int, default=12)
    parser.add_argument("--patch_size", type=int, default=4)
    parser.add_argument("--bottleneck", type=int, default=768)
    parser.add_argument("--dropout", type=float, default=0.05)
    parser.add_argument("--decoder", type=str, default=None,
                        choices=["gemma", "qwen"])

    args = parser.parse_args()
    output_path = args.output_path or f"eval_{args.model_type}.json"

    print(f"Evaluating: {args.model_type}")
    print(f"Checkpoint: {args.checkpoint}")
    print(f"Device: {DEVICE}")

    # Load model
    if args.model_type == "stage1":
        decoder, decoder_name = load_stage1_decoder(
            args.checkpoint, args.lora_rank, args.lora_alpha,
            args.lora_dropout, args.lora_layers, args.decoder)
        model = None
    else:
        model, detected_type = load_stage2_model(
            args.checkpoint, args.lora_rank, args.lora_alpha,
            args.lora_dropout, args.lora_layers, args.patch_size,
            args.bottleneck, args.dropout, args.decoder)
        decoder = None
        print(f"Detected model type from checkpoint: {detected_type}")

    # Load eval data
    print(f"\nLoading {args.num_samples} eval samples from HuggingFace...")
    hf_data = load_dataset("philip120/matlab-nl-pseudocode-v2", split="train[-20%:]")
    eval_samples = list(hf_data.select(range(min(args.num_samples, len(hf_data)))))

    # Eval
    scorer = rouge_scorer.RougeScorer(['rouge1', 'rouge2', 'rougeL'], use_stemmer=True)
    smoother = SmoothingFunction().method1
    results = []

    print(f"\nEvaluating {len(eval_samples)} samples...")
    for i, item in enumerate(eval_samples):
        code = item["code"]
        reference = item["nl"]

        if not code or not reference:
            continue
        if code.lstrip().startswith("classdef"):
            continue

        t0 = time.perf_counter()
        try:
            if args.model_type == "stage1":
                generated = generate_stage1(decoder, code, args.max_tokens)
            else:
                generated = model.generate(code, max_new_tokens=args.max_tokens)
        except Exception as e:
            print(f"  [{i}] generation failed: {e}")
            continue
        gen_time = time.perf_counter() - t0

        # ROUGE
        scores = scorer.score(reference, generated)

        # BLEU
        bleu = sentence_bleu(
            [reference.split()], generated.split(),
            smoothing_function=smoother
        )

        results.append({
            "code": code,
            "reference_description": reference,
            "generated_description": generated,
            "metrics": {
                "rouge1": scores['rouge1'].fmeasure,
                "rouge2": scores['rouge2'].fmeasure,
                "rougeL": scores['rougeL'].fmeasure,
                "bleu": bleu,
                "generation_time_s": round(gen_time, 3),
            }
        })

        if i < 5:
            print(f"\n  [{i}] ROUGE-L={scores['rougeL'].fmeasure:.4f}  BLEU={bleu:.4f}  time={gen_time:.2f}s")
            print(f"    ref: {reference[:100]}...")
            print(f"    gen: {generated[:100]}...")

    # Summary
    if results:
        avg_r1 = sum(r["metrics"]["rouge1"] for r in results) / len(results)
        avg_r2 = sum(r["metrics"]["rouge2"] for r in results) / len(results)
        avg_rl = sum(r["metrics"]["rougeL"] for r in results) / len(results)
        avg_bleu = sum(r["metrics"]["bleu"] for r in results) / len(results)
        avg_time = sum(r["metrics"]["generation_time_s"] for r in results) / len(results)

        print(f"\n{'='*60}")
        print(f"RESULTS: {args.model_type} ({len(results)} samples)")
        print(f"{'='*60}")
        print(f"  ROUGE-1:  {avg_r1:.4f}")
        print(f"  ROUGE-2:  {avg_r2:.4f}")
        print(f"  ROUGE-L:  {avg_rl:.4f}")
        print(f"  BLEU:     {avg_bleu:.4f}")
        print(f"  Avg time: {avg_time:.3f}s")

    # Save
    with open(output_path, "w") as f:
        json.dump(results, f, indent=4)
    print(f"\nResults saved to: {output_path}")


if __name__ == "__main__":
    main()
