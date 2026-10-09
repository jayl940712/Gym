#!/usr/bin/env python3
# SPDX-License-Identifier: Apache-2.0
# Adapted from 3DCodeBench; see third_party/NOTICE.md for provenance.
"""Text↔image similarity metric for the text-to-3D track.

For every instance in `results/<model>/`, computes cosine similarity
between each of the four rendered views and the input *text prompt*
using SigLIP-2 (`google/siglip2-so400m-patch16-naflex`). Aggregates
per-instance via mean-of-4 and max-of-4, then averages across the
212 instances.

Companion metric: `image_similarity.py` does rendered↔reference image
cosine similarity for the image-to-3D track.

Also computes a GT-image baseline using the reference renders in
`eval/data/<inst>/images/Image_*.png` against the same prompts —
gives an upper bound the model's renders can be compared against.

Two aggregate flavors are reported per metric:

    conditional   — averaged over instances that have all 4 renders
                    (i.e., rendered successfully). "If it works, how
                    well does it match?"
    penalized     — failed/missing renders count as 0, averaged over
                    all 212. "Overall fidelity, including failures."

Output: prints summary, writes JSON to
    `results/<model>/_metrics/text_image_similarity_siglip2.json`
including per-instance scores.

Usage:
    python eval/metrics/text_image_similarity.py --model gemini-3-flash-preview
"""

import argparse
import json
import time
from pathlib import Path

import torch
from PIL import Image
from transformers import AutoModel, AutoProcessor


EVAL_ROOT = Path(__file__).resolve().parent.parent
DEFAULT_RESULTS_ROOT = EVAL_ROOT / "results"
DEFAULT_DATA_ROOT = EVAL_ROOT / "data"

DEFAULT_MODEL = "google/siglip2-so400m-patch16-naflex"
VIEWS = ["Image_005.png", "Image_015.png", "Image_025.png", "Image_035.png"]


def parse_args():
    p = argparse.ArgumentParser(
        formatter_class=argparse.RawDescriptionHelpFormatter,
        description=__doc__,
    )
    p.add_argument("--model", required=True, help="Name of the inference model dir under results/")
    p.add_argument("--siglip-model", default=DEFAULT_MODEL, help="HF model id for SigLIP (default: SigLIP-2 SO/400M).")
    p.add_argument("--results-root", type=Path, default=DEFAULT_RESULTS_ROOT)
    p.add_argument("--data-root", type=Path, default=DEFAULT_DATA_ROOT)
    p.add_argument("--prompt-type", choices=["description", "instruction"], default="description")
    p.add_argument("--batch-size", type=int, default=16)
    p.add_argument("--device", default="cuda")
    p.add_argument("--instances", nargs="*", default=None)
    return p.parse_args()


def _as_tensor(out):
    """SigLIP-2 in transformers >=5 returns BaseModelOutputWithPooling from
    get_*_features; take the pooler_output. Earlier versions returned a
    Tensor directly — handle both."""
    if isinstance(out, torch.Tensor):
        return out
    return out.pooler_output


def encode_images(model, processor, paths, batch_size, device):
    """Return (N, D) normalized image embeddings for the given image paths."""
    embeds = []
    for i in range(0, len(paths), batch_size):
        batch = paths[i : i + batch_size]
        imgs = [Image.open(p).convert("RGB") for p in batch]
        inputs = processor(images=imgs, return_tensors="pt").to(device)
        with torch.no_grad():
            feats = _as_tensor(model.get_image_features(**inputs))
        feats = feats / feats.norm(dim=-1, keepdim=True)
        embeds.append(feats.cpu())
    return torch.cat(embeds, 0) if embeds else torch.zeros(0)


def encode_texts(model, processor, texts, batch_size, device):
    """Return (N, D) normalized text embeddings."""
    embeds = []
    for i in range(0, len(texts), batch_size):
        batch = texts[i : i + batch_size]
        inputs = processor(
            text=batch,
            return_tensors="pt",
            padding="max_length",
            truncation=True,
        ).to(device)
        with torch.no_grad():
            feats = _as_tensor(model.get_text_features(**inputs))
        feats = feats / feats.norm(dim=-1, keepdim=True)
        embeds.append(feats.cpu())
    return torch.cat(embeds, 0) if embeds else torch.zeros(0)


def main():
    args = parse_args()
    model_dir = args.results_root / args.model
    if not model_dir.exists():
        raise SystemExit(f"No such model dir: {model_dir}")

    instances = sorted(d for d in model_dir.iterdir() if d.is_dir() and not d.name.startswith("_"))
    if args.instances:
        keep = set(args.instances)
        instances = [d for d in instances if d.name in keep]

    # Collect per-instance data
    rows = []  # per instance: {name, prompt, render_paths, gt_paths}
    for inst in instances:
        prompt_file = inst / "prompt.txt"
        if not prompt_file.exists():
            continue
        prompt = prompt_file.read_text().strip()

        renders_dir = inst / "renders"
        render_paths = [(renders_dir / v) if (renders_dir / v).exists() else None for v in VIEWS]

        gt_dir = args.data_root / inst.name / "images"
        gt_paths = [(gt_dir / v) if (gt_dir / v).exists() else None for v in VIEWS]

        rows.append(
            {
                "instance": inst.name,
                "prompt": prompt,
                "render_paths": render_paths,
                "gt_paths": gt_paths,
            }
        )

    if not rows:
        raise SystemExit("No instances with prompt.txt found.")

    print(f"Loading SigLIP model: {args.siglip_model}")
    t0 = time.time()
    processor = AutoProcessor.from_pretrained(args.siglip_model)
    model = AutoModel.from_pretrained(args.siglip_model).to(args.device).eval()
    print(f"  loaded in {time.time() - t0:.1f}s")

    # ── Encode texts (one per instance) ──
    print(f"Encoding {len(rows)} prompts…")
    t0 = time.time()
    texts = [r["prompt"] for r in rows]
    text_embeds = encode_texts(model, processor, texts, args.batch_size, args.device)
    print(f"  texts done in {time.time() - t0:.1f}s, shape={tuple(text_embeds.shape)}")

    # ── Encode all images (renders + GT), keeping a mapping back ──
    flat_paths = []
    flat_idx = []  # (row_idx, slot, kind) — kind in {"r","g"}, slot in 0..3
    for ri, r in enumerate(rows):
        for slot, p in enumerate(r["render_paths"]):
            if p is not None:
                flat_paths.append(p)
                flat_idx.append((ri, slot, "r"))
        for slot, p in enumerate(r["gt_paths"]):
            if p is not None:
                flat_paths.append(p)
                flat_idx.append((ri, slot, "g"))

    print(f"Encoding {len(flat_paths)} images (renders + GT)…")
    t0 = time.time()
    img_embeds = encode_images(model, processor, flat_paths, args.batch_size, args.device)
    print(f"  images done in {time.time() - t0:.1f}s, shape={tuple(img_embeds.shape)}")

    # ── Compute similarities ──
    n = len(rows)
    sims_r = [[None] * 4 for _ in range(n)]  # rendered model output
    sims_g = [[None] * 4 for _ in range(n)]  # ground-truth Infinigen renders
    for k, (ri, slot, kind) in enumerate(flat_idx):
        sim = float((img_embeds[k] * text_embeds[ri]).sum())
        if kind == "r":
            sims_r[ri][slot] = sim
        else:
            sims_g[ri][slot] = sim

    # ── Per-instance aggregates ──
    per_instance = []
    for ri, r in enumerate(rows):
        rs = [s for s in sims_r[ri] if s is not None]
        gs = [s for s in sims_g[ri] if s is not None]
        per_instance.append(
            {
                "instance": r["instance"],
                "n_renders": len(rs),
                "n_gt": len(gs),
                "render_mean": float(sum(rs) / len(rs)) if rs else None,
                "render_max": float(max(rs)) if rs else None,
                "render_per_view": sims_r[ri],
                "gt_mean": float(sum(gs) / len(gs)) if gs else None,
                "gt_max": float(max(gs)) if gs else None,
                "gt_per_view": sims_g[ri],
            }
        )

    # ── Cross-instance aggregates ──
    def agg(values):
        vals = [v for v in values if v is not None]
        return float(sum(vals) / len(vals)) if vals else None

    # Conditional: only over instances that produced all 4 renders
    full_render = [pi for pi in per_instance if pi["n_renders"] == 4]
    cond_render_mean = agg([pi["render_mean"] for pi in full_render])
    cond_render_max = agg([pi["render_max"] for pi in full_render])

    # Penalized: failed/missing renders → 0
    pen_render_mean = sum((pi["render_mean"] or 0.0) for pi in per_instance) / n
    pen_render_max = sum((pi["render_max"] or 0.0) for pi in per_instance) / n

    # GT baseline (over instances that have all 4 GT images)
    full_gt = [pi for pi in per_instance if pi["n_gt"] == 4]
    gt_mean = agg([pi["gt_mean"] for pi in full_gt])
    gt_max = agg([pi["gt_max"] for pi in full_gt])

    summary = {
        "model": args.model,
        "siglip_model": args.siglip_model,
        "prompt_type": args.prompt_type,
        "n_instances": n,
        "n_full_render": len(full_render),
        "n_full_gt": len(full_gt),
        "render": {
            "conditional_mean_of_view_mean": cond_render_mean,
            "conditional_mean_of_view_max": cond_render_max,
            "penalized_mean_of_view_mean": pen_render_mean,
            "penalized_mean_of_view_max": pen_render_max,
        },
        "gt_baseline": {
            "mean_of_view_mean": gt_mean,
            "mean_of_view_max": gt_max,
        },
        "per_instance": per_instance,
    }

    out_dir = model_dir / "_metrics"
    out_dir.mkdir(exist_ok=True)
    out_path = out_dir / "text_image_similarity_siglip2.json"
    out_path.write_text(json.dumps(summary, indent=2))

    # ── Print ──
    def fmt(v):
        return f"{v:.4f}" if isinstance(v, float) else "  --  "

    print()
    print(f"=== SigLIP-2 similarity — {args.model} ===")
    print(f"  Instances:           {n}")
    print(f"  With all 4 renders:  {len(full_render)}")
    print(f"  With all 4 GT imgs:  {len(full_gt)}")
    print()
    print("Model renders:")
    print(f"  conditional  mean-of-mean = {fmt(cond_render_mean)}    mean-of-max = {fmt(cond_render_max)}")
    print(f"  penalized    mean-of-mean = {fmt(pen_render_mean)}    mean-of-max = {fmt(pen_render_max)}")
    print("GT baseline (Infinigen renders):")
    print(f"               mean-of-mean = {fmt(gt_mean)}    mean-of-max = {fmt(gt_max)}")
    print()
    print(f"Saved: {out_path}")


if __name__ == "__main__":
    main()
