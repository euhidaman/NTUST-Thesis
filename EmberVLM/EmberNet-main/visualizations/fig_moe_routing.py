"""
fig_moe_routing.py
==================
Figure 3 — MoE expert routing patterns across vision-language domains.

Scientific story
----------------
If the MoE architecture is working as intended, the 8 domain experts
should exhibit specialization: "vision_ocr" should dominate on TextVQA /
DocVQA, "code_math_chart" on ChartQA, "spatial_scene"/"spatial_reasoning"
on VQAv2/GQA, etc.  This figure provides empirical evidence of that
specialization through routing frequency matrices and domain-conditional
expert usage profiles.

Panels
------
A) Routing frequency matrix (datasets × experts) — heatmap.
   Each cell = fraction of tokens from that dataset routed to that expert.
B) Per-domain expert load bar chart: top-2 dominant experts highlighted.
C) Expert routing load over decoder depth (which layers specialize more).

Intended paper usage
--------------------
Figure 3, Section 4.2 "Expert Specialization Analysis".
Can also serve as a supplemental routing analysis table.
"""

from __future__ import annotations

import sys
from pathlib import Path
from typing import Optional, Dict, List, Tuple
import numpy as np
import matplotlib.pyplot as plt
import matplotlib.gridspec as gridspec
from matplotlib.colors import LogNorm

sys.path.insert(0, str(Path(__file__).parent.parent))
from visualizations.config import (
    VIZ_CONFIG, EXPERT_NAMES, EXPERT_COLORS, DATASET_DOMAINS, apply_mpl_style, skip_no_data
)

apply_mpl_style()


# ---------------------------------------------------------------------------
# Dataset / expert metadata
# ---------------------------------------------------------------------------
_EVAL_DATASETS = [
    "TextVQA",  "DocVQA",    "OCR-VQA",
    "ChartQA",  "MathVista",
    "VQAv2",    "GQA",
    "ScienceQA","A-OKVQA",
]

# Expected dominant expert(s) per dataset (by index 0-7)
_EXPECTED_EXPERT = {
    "TextVQA":   (0, 1),   # vision_ocr, vision_diagram
    "DocVQA":    (0, 1),
    "OCR-VQA":   (0, 1),
    "ChartQA":   (2, 3),   # code_math_chart, code_math_formula
    "MathVista": (3, 2),
    "VQAv2":     (4, 5),   # spatial_scene, spatial_reasoning
    "GQA":       (5, 4),
    "ScienceQA": (6, 7),   # agentic_knowledge, agentic_reasoning
    "A-OKVQA":   (6, 7),
}


# ---------------------------------------------------------------------------
# Synthetic routing data generator
# ---------------------------------------------------------------------------

def _synthetic_routing_matrix(
    datasets: List[str],
    num_experts: int = 8,
    num_layers: int = 16,
    seed: int = 42,
) -> Tuple[np.ndarray, np.ndarray]:
    """
    Generate a realistic synthetic routing frequency matrix.

    Returns
    -------
    routing_matrix : (num_datasets, num_experts) float array — fraction per expert
    layer_matrix   : (num_layers, num_experts) float array — expert load by layer
    """
    rng = np.random.default_rng(seed)
    routing = np.zeros((len(datasets), num_experts))

    for i, ds in enumerate(datasets):
        expected = _EXPECTED_EXPERT.get(ds, (rng.integers(0, 4),))
        base = np.ones(num_experts) * 0.04
        for e in expected:
            base[e] += 0.30 + rng.uniform(0.0, 0.15)
        # Add small noise
        base += rng.uniform(0, 0.03, size=num_experts)
        # Normalise to sum = 1
        routing[i] = base / base.sum()

    # Layer routing: deep layers specialize more
    layer_routing = np.zeros((num_layers, num_experts))
    for layer in range(num_layers):
        depth_factor = layer / (num_layers - 1)  # 0..1
        base = np.ones(num_experts) * (1 / num_experts)
        # Simulate increasing specialization with depth
        dom_expert = layer % num_experts
        base[dom_expert] += 0.20 * depth_factor
        noise = rng.uniform(0, 0.02, size=num_experts)
        base = base + noise
        layer_routing[layer] = base / base.sum()

    return routing, layer_routing


# ---------------------------------------------------------------------------
# Real extraction
# ---------------------------------------------------------------------------

def _extract_routing_from_model(model, eval_datasets: Optional[List[str]] = None) -> Tuple[np.ndarray, np.ndarray]:
    """
    Run representative prompts per dataset through the model and collect routing.
    Falls back to synthetic data on any error.
    """
    try:
        import torch
        from models.bitnet_moe import BitNetMoEDecoder

        if not (hasattr(model, "decoder") and hasattr(model.decoder, "layers")):
            raise RuntimeError("decoder not accessible")

        datasets = eval_datasets or _EVAL_DATASETS
        num_experts = len(model.decoder.layers[0].moe.experts)
        num_layers  = len(model.decoder.layers)

        # Representative prompts per dataset for realistic routing measurement
        _DATASET_PROMPTS = {
            "TextVQA":   "What text is written on the sign in this image?",
            "DocVQA":    "What is the total amount shown in this document?",
            "OCR-VQA":   "What is the title of this book?",
            "ChartQA":   "What is the highest value shown in this chart?",
            "MathVista": "Solve the math problem shown in the image.",
            "VQAv2":     "How many people are visible in this image?",
            "GQA":       "What is to the left of the table?",
            "ScienceQA": "Which of the following best explains the diagram?",
            "A-OKVQA":   "What activity are the people in this image doing?",
        }

        # Hook into router logits for each layer
        router_logits_per_layer: Dict[int, List[torch.Tensor]] = {i: [] for i in range(num_layers)}

        def make_hook(layer_idx):
            def hook(m, inp, out):
                router_logits_per_layer[layer_idx].append(out[1].detach().cpu())
            return hook

        handles = []
        for i, layer in enumerate(model.decoder.layers):
            handles.append(layer.register_forward_hook(make_hook(i)))

        routing_matrix = np.zeros((len(datasets), num_experts))
        layer_load     = np.zeros((num_layers, num_experts))

        device = next(model.parameters()).device

        model.eval()
        with torch.no_grad():
            for di, ds in enumerate(datasets):
                prompt_text = _DATASET_PROMPTS.get(ds, f"Describe this {ds} image.")
                if hasattr(model, "tokenizer") and model.tokenizer is not None:
                    tok_out = model.tokenizer(prompt_text, return_tensors="pt")
                    input_ids = tok_out["input_ids"].to(device)
                else:
                    input_ids = torch.randint(1, 1000, (1, 16), device=device)
                try:
                    _ = model.decoder(input_ids=input_ids)
                except Exception:
                    pass

                # Aggregate over all layers and tokens
                for li in range(num_layers):
                    for logit_batch in router_logits_per_layer[li]:
                        probs = torch.softmax(logit_batch.float(), dim=-1)
                        routing_matrix[di] += probs.mean(dim=0).numpy()
                        layer_load[li]     += probs.mean(dim=0).numpy()
                    router_logits_per_layer[li].clear()

        for h in handles:
            h.remove()

        # Normalise rows
        row_sums = routing_matrix.sum(axis=1, keepdims=True)
        row_sums = np.where(row_sums == 0, 1, row_sums)
        routing_matrix /= row_sums

        layer_sums = layer_load.sum(axis=1, keepdims=True)
        layer_sums = np.where(layer_sums == 0, 1, layer_sums)
        layer_load /= layer_sums

        return routing_matrix, layer_load

    except Exception as e:
        print(f"[fig_moe_routing] Real extraction failed: {e}")
        return None, None


# ---------------------------------------------------------------------------
# Main
# ---------------------------------------------------------------------------

def generate(save_dir: Optional[Path] = None, model=None) -> Path:
    """
    Generate Figure 3 and save it.

    Parameters
    ----------
    save_dir : Path, optional
        Output directory.  Defaults to plots/paper_figures/.
    model : EmberNetVLM, optional
        Live model for real routing extraction.

    Returns
    -------
    Path : path to the saved PNG.
    """
    if save_dir is None:
        save_dir = Path("plots/paper_figures")
    save_dir.mkdir(parents=True, exist_ok=True)

    datasets = _EVAL_DATASETS
    _nl = "\n"
    expert_short = [f"E{i}{_nl}{n.replace('_', '_' + _nl)}" for i, n in enumerate(EXPERT_NAMES)]
    expert_colors = [EXPERT_COLORS[n] for n in EXPERT_NAMES]

    if model is None:
        skip_no_data("fig3_moe_routing")
        return save_dir / "fig3_moe_routing.png"

    routing_matrix, layer_matrix = _extract_routing_from_model(model, datasets)
    if routing_matrix is None:
        skip_no_data("fig3_moe_routing (extraction failed)")
        return save_dir / "fig3_moe_routing.png"

    num_layers = layer_matrix.shape[0]

    fig = plt.figure(figsize=(18, 12), dpi=VIZ_CONFIG["dpi"])
    gs  = gridspec.GridSpec(2, 2, hspace=0.55, wspace=0.40)

    ax_heat  = fig.add_subplot(gs[0, :])   # top: full-width heatmap
    ax_bar   = fig.add_subplot(gs[1, 0])   # bottom-left: domain bars
    ax_layer = fig.add_subplot(gs[1, 1])   # bottom-right: per-layer load

    # ------------------------------------------------------------------
    # Panel A — routing frequency heatmap (datasets × experts)
    # ------------------------------------------------------------------
    im = ax_heat.imshow(routing_matrix * 100, aspect="auto", cmap="YlOrRd",
                         vmin=0, vmax=routing_matrix.max() * 100)
    ax_heat.set_xticks(range(8))
    ax_heat.set_xticklabels(expert_short, fontsize=7.5, ha="center", multialignment="center")
    ax_heat.set_yticks(range(len(datasets)))
    ax_heat.set_yticklabels(datasets, fontsize=9)
    ax_heat.set_title("A) Expert Routing Frequency per Dataset (% tokens routed to each expert)",
                       fontsize=10, fontweight="bold")
    plt.colorbar(im, ax=ax_heat, fraction=0.015, pad=0.02, label="% tokens routed")

    # Annotate cells
    for i in range(len(datasets)):
        for j in range(8):
            val = routing_matrix[i, j] * 100
            ax_heat.text(j, i, f"{val:.1f}", ha="center", va="center",
                          fontsize=7, color="black" if val < 30 else "white")

    # Highlight expected dominant cells
    for i, ds in enumerate(datasets):
        for e in _EXPECTED_EXPERT.get(ds, ()):
            ax_heat.add_patch(plt.Rectangle(
                (e - 0.48, i - 0.48), 0.96, 0.96,
                fill=False, edgecolor="#333333", lw=1.8, zorder=5
            ))

    ax_heat.text(0.99, -0.06,
                 "□ = expected dominant expert per dataset domain",
                 transform=ax_heat.transAxes, ha="right", va="top", fontsize=8, style="italic")

    # ------------------------------------------------------------------
    # Panel B — mean expert load per dataset (bar chart)
    # ------------------------------------------------------------------
    x = np.arange(8)
    bar_w = 0.65
    mean_load = routing_matrix.mean(axis=0) * 100
    bars = ax_bar.bar(x, mean_load, bar_w, color=expert_colors, edgecolor="white", lw=0.8)
    ax_bar.axhline(y=100 / 8, color="gray", ls="--", lw=1.2, label=f"Uniform ({100/8:.1f}%)")
    ax_bar.set_xticks(x)
    ax_bar.set_xticklabels([f"E{i}" for i in range(8)], fontsize=8.5)
    ax_bar.set_ylabel("Mean routing load (%)", fontsize=9)
    ax_bar.set_title("B) Mean Expert Load\n(averaged across all evaluation datasets)",
                      fontsize=9.5, fontweight="bold")
    ax_bar.legend(fontsize=8, framealpha=0.85)
    for bar, v in zip(bars, mean_load):
        ax_bar.text(bar.get_x() + bar.get_width() / 2, bar.get_height() + 0.3,
                     f"{v:.1f}", ha="center", va="bottom", fontsize=7.5, fontweight="bold")

    # ------------------------------------------------------------------
    # Panel C — expert load across decoder depth
    # ------------------------------------------------------------------
    layer_ids = np.arange(num_layers)
    for e_idx, (ename, ecolor) in enumerate(zip(EXPERT_NAMES, expert_colors)):
        ax_layer.plot(layer_ids, layer_matrix[:, e_idx] * 100,
                       color=ecolor, lw=1.5, label=f"E{e_idx}",
                       marker="o", markersize=3)
    ax_layer.axhline(y=100 / 8, color="gray", ls="--", lw=1.0, alpha=0.7)
    ax_layer.set_xlabel("Decoder layer index", fontsize=9)
    ax_layer.set_ylabel("Routing load (%)", fontsize=9)
    ax_layer.set_title("C) Expert Routing Load vs. Decoder Depth",
                        fontsize=9.5, fontweight="bold")
    ax_layer.legend(fontsize=6.5, loc="upper left", ncol=2, framealpha=0.85)
    ax_layer.set_xticks(layer_ids[::2])

    fig.suptitle(
        "Figure 3 — MoE Expert Specialization: Routing Patterns Across Vision-Language Domains",
        fontsize=12, fontweight="bold", y=1.01
    )

    out_pdf = save_dir / "fig3_moe_routing.pdf"
    out_png = save_dir / "fig3_moe_routing.png"
    fig.savefig(out_pdf, bbox_inches="tight")
    fig.savefig(out_png, bbox_inches="tight")
    plt.close(fig)
    print(f"[fig3] Saved → {out_png}")
    return out_png


if __name__ == "__main__":
    generate()
