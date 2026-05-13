"""
fig_qualitative_grid.py
=======================
Figure 7 — Qualitative examples panel: image + baseline + VA-refined answers.

Scientific story
----------------
Quantitative plots (Figures 5–6) show the statistical picture; this figure
provides human-readable, visually intuitive evidence that the VA Refiner
changes answers in meaningful, correct directions on representative samples.

For 4–6 image–question pairs drawn from different domains (OCR, charts,
outdoor scenes, counting), we render:
  • Thumbnail of the image (or a coloured placeholder if unavailable).
  • Question string.
  • Model answer WITHOUT VA Refiner (potentially hallucinated portions
    highlighted in red).
  • Model answer WITH VA Refiner (corrections / suppressions highlighted
    in blue; prefix disclaimers in italic).
  • A small inline sparkline of p_VA over token positions.

The result is a single multi-panel PDF/PNG ready for direct inclusion
in a paper as "Figure 7: Qualitative Examples".

Intended paper usage
--------------------
Figure 7 in the main text or appendix, Section 5.4 "Qualitative Analysis".
Typically 4–6 rows × 1 wide figure (landscape).
"""

from __future__ import annotations

import sys
import textwrap
from pathlib import Path
from typing import Optional, List, Dict, Any
import numpy as np
import matplotlib.pyplot as plt
import matplotlib.gridspec as gridspec


sys.path.insert(0, str(Path(__file__).parent.parent))
from visualizations.config import VIZ_CONFIG, apply_mpl_style, skip_no_data

apply_mpl_style()

# ---------------------------------------------------------------------------
# Sample definitions
# ---------------------------------------------------------------------------
_CYAN  = "#1f77b4"
_RED   = "#d62728"
_GRAY  = "#888888"
_GREEN = "#2ca02c"

# Each sample: (domain, question, answer_no_va, answer_va, halluc_tokens, p_va_trace)
_QUAL_SAMPLES = [
    dict(
        domain="OCR / Document",
        img_color=(230, 230, 255),
        hf_source=dict(hf_name="lmms-lab/DocVQA", hf_config="DocVQA", split="test", index=0),
        question="What is the invoice total?",
        answer_no_va="The invoice total is $1,250.00 with a delivery charge of $35.",
        answer_va="I might be wrong, but the invoice total is $1,250.00 with a delivery charge of $35.",
        halluc_words=["$35"],
        pva_trace=[0.12, 0.09, 0.11, 0.08, 0.10, 0.13, 0.11, 0.69, 0.71, 0.68, 0.14, 0.12, 0.10],
    ),
    dict(
        domain="Chart (ChartQA)",
        img_color=(230, 255, 230),
        hf_source=dict(hf_name="ahmed-masry/ChartQA", hf_config="default", split="test", index=0),
        question="What is the peak year for sales?",
        answer_no_va="The peak year for sales is 2019, with approximately 4.2 million units.",
        answer_va="The peak year for sales is 2019, with approximately 4.2 million units.",
        halluc_words=[],
        pva_trace=[0.10, 0.08, 0.11, 0.09, 0.07, 0.12, 0.10, 0.11, 0.13, 0.10, 0.09, 0.08, 0.10, 0.11],
    ),
    dict(
        domain="Outdoor Scene (VQAv2)",
        img_color=(255, 240, 200),
        hf_source=dict(hf_name="lmms-lab/VQAv2", hf_config="default", split="test", index=0),
        question="How many cars are visible on the road?",
        answer_no_va="There are four cars on the road, including a red one on the left.",
        answer_va="There are four cars on the road, including a red one on the left.",
        halluc_words=["four", "red"],
        pva_trace=[0.11, 0.08, 0.72, 0.70, 0.12, 0.10, 0.13, 0.74, 0.73, 0.11, 0.10, 0.09, 0.11],
    ),
    dict(
        domain="Science (ScienceQA)",
        img_color=(255, 230, 230),
        hf_source=dict(hf_name="derek-thomas/ScienceQA", hf_config="default", split="test", index=0),
        question="What type of circuit is shown in the diagram?",
        answer_no_va="The diagram shows a parallel circuit with three resistors.",
        answer_va="The diagram shows a parallel circuit with three resistors.",
        halluc_words=[],
        pva_trace=[0.10, 0.11, 0.09, 0.12, 0.08, 0.11, 0.10, 0.13, 0.12, 0.09],
    ),
    dict(
        domain="Text Reading (TextVQA)",
        img_color=(240, 220, 255),
        hf_source=dict(hf_name="lmms-lab/textvqa", hf_config="default", split="test", index=0),
        question="What brand name is visible on the storefront?",
        answer_no_va="The storefront shows the brand name WALMART in large capital letters.",
        answer_va="I cannot see that clearly, but the storefront may show WALMART.",
        halluc_words=["WALMART", "large", "capital"],
        pva_trace=[0.10, 0.09, 0.11, 0.77, 0.82, 0.80, 0.13, 0.12, 0.10, 0.11],
    ),
]


# ---------------------------------------------------------------------------
# Drawing helpers
# ---------------------------------------------------------------------------

def _load_hf_image(hf_name, hf_config="default", split="test", index=0):
    """Load a single image + metadata from a HuggingFace dataset via streaming."""
    try:
        from datasets import load_dataset
        from PIL import Image as PILImage
        ds = load_dataset(hf_name, hf_config, split=split, streaming=True)
        for i, item in enumerate(ds):
            if i == index:
                img = item.get("image") or item.get("img") or item.get("picture")
                if img is None:
                    return None, dict(item)
                if isinstance(img, PILImage.Image):
                    return img.convert("RGB"), dict(item)
                if isinstance(img, str) and img.startswith("http"):
                    import requests
                    from io import BytesIO
                    r = requests.get(img, timeout=15)
                    return PILImage.open(BytesIO(r.content)).convert("RGB"), dict(item)
                if isinstance(img, str) and Path(img).exists():
                    return PILImage.open(img).convert("RGB"), dict(item)
                return None, dict(item)
            if i > index + 10:
                break
    except Exception as e:
        print(f"  [load_hf_image] {hf_name}: {e}")
    return None, {}


def _render_image_cell(ax, sample):
    """Display a real dataset image or colored placeholder in the axes."""
    pil_img = sample.get("_pil_image")
    domain = sample.get("domain", "")
    if pil_img is not None:
        ax.imshow(pil_img)
        ax.set_xticks([])
        ax.set_yticks([])
    else:
        rgb = sample.get("img_color", (220, 220, 220))
        ax.set_xlim(0, 1)
        ax.set_ylim(0, 1)
        ax.set_xticks([])
        ax.set_yticks([])
        ax.set_facecolor(tuple(c / 255.0 for c in rgb))
        ax.text(0.5, 0.5, domain.replace(" ", "\n"),
                ha="center", va="center", fontsize=7.5, fontweight="bold",
                color="#333333", multialignment="center")
    for spine in ax.spines.values():
        spine.set_linewidth(0.5)
        spine.set_edgecolor("#888888")
    ax.text(0.5, 0.02, domain, ha="center", va="bottom", fontsize=5.5,
            color="#555555", style="italic",
            bbox=dict(boxstyle="round,pad=0.15", fc="white", ec="none", alpha=0.75),
            transform=ax.transAxes)


def _render_answer_with_highlights(ax, text: str, halluc_words: List[str],
                                    is_va: bool, title: str):
    """Render an answer string with hallucinated words highlighted."""
    ax.set_xlim(0, 1)
    ax.set_ylim(0, 1)
    ax.axis("off")

    # Title
    title_color = _CYAN if is_va else _RED if halluc_words else _GRAY
    ax.text(0.0, 0.96, title, ha="left", va="top", fontsize=8, fontweight="bold",
            color=title_color, transform=ax.transAxes)

    # Wrap text
    wrapped = textwrap.fill(text, width=52)
    lines   = wrapped.split("\n")

    y_start = 0.82
    line_h  = 0.14
    for li, line in enumerate(lines[:5]):
        y = y_start - li * line_h
        words = line.split()
        x_cursor = 0.0
        char_w   = 0.016  # approximate
        for word in words:
            clean_word = word.strip(".,!?\"'")
            is_hallu   = any(h.lower() in clean_word.lower() for h in halluc_words)
            color      = (_RED   if (is_hallu and not is_va) else
                          _CYAN  if (is_hallu and is_va) else
                          "#222222")
            fontweight = "bold" if is_hallu else "normal"
            # Colour the VA prefix ("I might be wrong, …" / "I cannot see …")
            _is_prefix_line = is_va and (text.startswith("I might") or text.startswith("I cannot"))
            if _is_prefix_line and li == 0:
                    color      = "#7b2d8b"
                    fontweight = "bold"
            ax.text(x_cursor, y, word + " ", ha="left", va="top", fontsize=7.8,
                    color=color, fontweight=fontweight, transform=ax.transAxes)
            x_cursor += (len(word) + 1) * char_w
            if x_cursor > 0.95:
                x_cursor = 0.0
                y -= line_h * 0.7


def _draw_sparkline(ax, pva_trace: List[float]):
    """Draw a compact p_VA sparkline."""
    x = np.arange(len(pva_trace))
    y = np.array(pva_trace)
    ax.fill_between(x, y, alpha=0.25, color=_RED)
    ax.plot(x, y, color=_RED, lw=1.4)
    ax.axhline(y=0.65, color="gray", ls="--", lw=0.8, alpha=0.7)
    ax.set_xlim(0, max(len(pva_trace) - 1, 1))
    ax.set_ylim(0, 1.05)
    ax.set_xticks([])
    ax.set_yticks([0, 0.5, 1.0])
    ax.set_yticklabels(["0", "0.5", "1"], fontsize=6)
    ax.set_xlabel("token pos", fontsize=6.5)
    ax.set_ylabel("p_VA", fontsize=6.5)
    ax.set_title("p_VA trace", fontsize=6.5, pad=2)
    for spine in ["top", "right"]:
        ax.spines[spine].set_visible(False)


# ---------------------------------------------------------------------------
# Main
# ---------------------------------------------------------------------------

def generate(
    save_dir: Optional[Path] = None,
    model=None,
    samples: Optional[List[Dict[str, Any]]] = None,
) -> Path:
    """
    Generate Figure 7 qualitative grid and save it.

    Parameters
    ----------
    save_dir : Path, optional
        Output directory.  Defaults to plots/paper_figures/.
    model : EmberNetVLM, optional
        If given, real model inference replaces synthetic answers.
    samples : list of dicts, optional
        Override the built-in sample list.

    Returns
    -------
    Path : path to saved PNG.
    """
    if save_dir is None:
        save_dir = Path("plots/paper_figures")
    save_dir.mkdir(parents=True, exist_ok=True)

    samples = samples or _QUAL_SAMPLES

    if model is None:
        skip_no_data("fig7_qualitative_grid")
        return save_dir / "fig7_qualitative_grid.png"

    # Pre-load real images from HuggingFace datasets
    for samp in samples:
        hf_src = samp.get("hf_source")
        if hf_src and "_pil_image" not in samp:
            pil_img, raw = _load_hf_image(**hf_src)
            if pil_img is not None:
                samp["_pil_image"] = pil_img
                q = raw.get("question") or raw.get("query", "")
                if q:
                    samp["question"] = q

    # Try real model inference
    if model is not None:
        try:
            import torch
            from PIL import Image as PILImage
            for samp in samples:
                img = samp.get("_pil_image")
                if img is None:
                    rgb = samp.get("img_color", (220, 220, 220))
                    img = PILImage.new("RGB", (224, 224), color=rgb)
                q    = samp["question"]

                # Without VA
                if model.va_refiner is not None:
                    model.set_va_refiner(None)
                with torch.no_grad():
                    ans_no = model.generate(image=img, prompt=q, max_new_tokens=64)
                samp["answer_no_va"] = ans_no

                # With VA
                from models.va_refiner import VARefiner, VARefinerConfig
                va_cfg = VARefinerConfig(use_va_refiner=True)
                refiner = VARefiner(model, va_cfg, model.tokenizer)
                model.set_va_refiner(refiner)
                with torch.no_grad():
                    ans_va = model.generate(image=img, prompt=q, max_new_tokens=64)
                samp["answer_va"] = ans_va
                scores = refiner.get_va_scores()
                if scores:
                    samp["pva_trace"] = list(scores)
        except Exception as e:
            skip_no_data(f"fig7_qualitative_grid (inference failed: {e})")
            return save_dir / "fig7_qualitative_grid.png"

    n = len(samples)
    # Layout: each row = [image | no-VA answer | VA answer | sparkline]
    # Proportions: 0.15 | 0.38 | 0.38 | 0.09
    fig = plt.figure(figsize=(18, 3.4 * n), dpi=VIZ_CONFIG["dpi"])
    gs  = gridspec.GridSpec(
        n, 4,
        width_ratios=[0.15, 0.38, 0.38, 0.09],
        hspace=0.55, wspace=0.25
    )

    for row, samp in enumerate(samples):
        ax_img    = fig.add_subplot(gs[row, 0])
        ax_no_va  = fig.add_subplot(gs[row, 1])
        ax_va     = fig.add_subplot(gs[row, 2])
        ax_spark  = fig.add_subplot(gs[row, 3])

        _render_image_cell(ax_img, samp)

        # Question label above the row
        ax_img.set_title(f"Q: {samp['question']}", fontsize=7.5,
                          loc="left", pad=3, fontweight="bold")

        _render_answer_with_highlights(
            ax_no_va, samp["answer_no_va"], samp.get("halluc_words", []),
            is_va=False, title="Without VA Refiner"
        )
        _render_answer_with_highlights(
            ax_va, samp["answer_va"], samp.get("halluc_words", []),
            is_va=True, title="With VA Refiner"
        )
        _draw_sparkline(ax_spark, samp.get("pva_trace", [0.1] * 10))

    # Column headers
    fig.text(0.065, 1.005, "Image", ha="center", fontsize=9, fontweight="bold")
    fig.text(0.350, 1.005, "Baseline (No VA Refiner)",
             ha="center", fontsize=9, fontweight="bold", color=_RED)
    fig.text(0.705, 1.005, "VA-Refined Answer",
             ha="center", fontsize=9, fontweight="bold", color=_CYAN)

    # Legend note
    fig.text(
        0.5, -0.012,
        "Red text = hallucinated token (no VA) or suppressed token (VA) | "
        "Blue text = corrected / retained by VA | "
        "Purple = VA uncertainty prefix",
        ha="center", fontsize=7.5, color="#555555"
    )

    fig.suptitle(
        "Figure 7 — Qualitative Examples: Baseline vs. VA-Refined Answers Across Domains",
        fontsize=12, fontweight="bold", y=1.025
    )

    out_pdf = save_dir / "fig7_qualitative_grid.pdf"
    out_png = save_dir / "fig7_qualitative_grid.png"
    fig.savefig(out_pdf, bbox_inches="tight")
    fig.savefig(out_png, bbox_inches="tight")
    plt.close(fig)
    print(f"[fig7] Saved → {out_png}")
    return out_png


if __name__ == "__main__":
    generate()
