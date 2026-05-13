"""
fig_ternary_stats.py
====================
Figure 2 — Ternary weight distribution and activation statistics.

Scientific story
----------------
BitNet-b1.58 promises weights constrained to {-1, 0, +1}; Figure 2 verifies
this property empirically across all BitLinear modules.  We show per-layer
sparsity (fraction of zero weights) and the ternary composition ({-1}/%{0}/%{+1})
separately for:
  - Attention projections  (Q/K/V/O)
  - Expert FFN layers      (gate/up/down) per each of the 8 domain experts
  - Shared expert FFN      (special focus — VA Refiner hooks here)
  - Vision projector       (ternary bridge between vision and language)

A high zero fraction (sparsity) indicates the model has learned selective,
sparse representations, consistent with mixture-of-experts design goals.

Intended paper usage
--------------------
Figure 2 in the main text ("Quantization Properties", Section 3.2).
The sparsity heatmap can also appear in supplemental material.
"""

from __future__ import annotations

import sys
from pathlib import Path
from typing import Optional, Dict, List
import numpy as np
import matplotlib.pyplot as plt
import matplotlib.gridspec as gridspec
from matplotlib.colors import Normalize
from matplotlib.cm import ScalarMappable

sys.path.insert(0, str(Path(__file__).parent.parent))
from visualizations.config import VIZ_CONFIG, EXPERT_NAMES, EXPERT_COLORS, apply_mpl_style, skip_no_data

apply_mpl_style()

_PALETTE = {"neg": "#d62728", "zero": "#aec7e8", "pos": "#1f77b4"}


# ---------------------------------------------------------------------------
# Synthetic data generator (used when no model is available)
# ---------------------------------------------------------------------------

def _synthetic_stats(num_layers: int = 16, num_experts: int = 8) -> Dict:
    """
    Generate realistic synthetic ternary weight statistics.

    Returns a dict with keys:
      attention_stats   : list of dicts, one per layer
      expert_stats      : list of list of dicts (layer × expert)
      shared_stats      : list of dicts, one per layer
      projector_stats   : list of dicts (fc1, fc2)
    """
    rng = np.random.default_rng(42)

    def _rand_ternary(
        zero_frac: float = 0.35,
        neg_bias: float = 0.0
    ) -> Dict[str, float]:
        z = np.clip(rng.normal(zero_frac, 0.04), 0.10, 0.65)
        remaining = 1 - z
        neg = remaining * np.clip(0.50 + neg_bias + rng.normal(0, 0.03), 0.35, 0.65)
        pos = remaining - neg
        return {"neg": float(neg), "zero": float(z), "pos": float(pos)}

    attn_stats = [
        {proj: _rand_ternary(0.30 + 0.01 * i) for proj in ["q_proj", "k_proj", "v_proj", "o_proj"]}
        for i in range(num_layers)
    ]
    expert_stats = [
        [
            {proj: _rand_ternary(0.35 + 0.015 * i + 0.005 * e)
             for proj in ["gate_proj", "up_proj", "down_proj"]}
            for e in range(num_experts)
        ]
        for i in range(num_layers)
    ]
    shared_stats = [
        {proj: _rand_ternary(0.38 + 0.012 * i)
         for proj in ["gate_proj", "up_proj", "down_proj"]}
        for i in range(num_layers)
    ]
    projector_stats = [
        {"fc1": _rand_ternary(0.28)},
        {"fc2": _rand_ternary(0.30)},
    ]
    return dict(
        attention_stats=attn_stats,
        expert_stats=expert_stats,
        shared_stats=shared_stats,
        projector_stats=projector_stats,
    )


# ---------------------------------------------------------------------------
# Real extraction
# ---------------------------------------------------------------------------

def _extract_stats_from_model(model) -> Dict:
    """Extract ternary composition from all BitLinear modules in the model."""
    try:
        from models.bitnet_moe import BitLinear, weight_quant
    except ImportError:
        return None

    def _ternary_fracs(module) -> Dict[str, float]:
        w = weight_quant(module.weight).detach().cpu().float()
        total = w.numel()
        neg_f  = float((w < -0.5).sum()) / total
        zero_f = float((w.abs() < 0.5).sum()) / total
        pos_f  = float((w > 0.5).sum()) / total
        return {"neg": neg_f, "zero": zero_f, "pos": pos_f}

    if not (hasattr(model, "decoder") and hasattr(model.decoder, "layers")):
        return None

    num_layers = len(model.decoder.layers)
    attn_stats  = []
    expert_stats = []
    shared_stats = []

    for layer in model.decoder.layers:
        attn = layer.attention
        attn_stats.append({
            "q_proj": _ternary_fracs(attn.q_proj),
            "k_proj": _ternary_fracs(attn.k_proj),
            "v_proj": _ternary_fracs(attn.v_proj),
            "o_proj": _ternary_fracs(attn.o_proj),
        })
        moe = layer.moe
        layer_experts = []
        for exp in moe.experts:
            layer_experts.append({
                "gate_proj": _ternary_fracs(exp.gate_proj),
                "up_proj":   _ternary_fracs(exp.up_proj),
                "down_proj": _ternary_fracs(exp.down_proj),
            })
        expert_stats.append(layer_experts)
        shared_stats.append({
            "gate_proj": _ternary_fracs(moe.shared_expert.gate_proj),
            "up_proj":   _ternary_fracs(moe.shared_expert.up_proj),
            "down_proj": _ternary_fracs(moe.shared_expert.down_proj),
        })

    projector_stats = []
    if hasattr(model, "projector"):
        proj = model.projector
        for attr in ["fc1", "fc2"]:
            if hasattr(proj, attr) and isinstance(getattr(proj, attr), BitLinear):
                projector_stats.append({attr: _ternary_fracs(getattr(proj, attr))})

    return dict(
        attention_stats=attn_stats,
        expert_stats=expert_stats,
        shared_stats=shared_stats,
        projector_stats=projector_stats if projector_stats else [],
    )


# ---------------------------------------------------------------------------
# Plotting helpers
# ---------------------------------------------------------------------------

def _zero_fraction_matrix(stats_per_layer: List, proj_keys: List[str]) -> np.ndarray:
    """Build [layers × projections] zero-fraction matrix."""
    mat = np.zeros((len(stats_per_layer), len(proj_keys)))
    for i, layer_s in enumerate(stats_per_layer):
        for j, pk in enumerate(proj_keys):
            if isinstance(layer_s, dict) and pk in layer_s:
                mat[i, j] = layer_s[pk]["zero"]
    return mat


def _draw_sparsity_heatmap(ax, matrix: np.ndarray, row_labels: List[str],
                            col_labels: List[str], title: str):
    """Annotated heatmap of zero fractions (sparsity)."""
    im = ax.imshow(matrix, aspect="auto", vmin=0.0, vmax=0.7,
                   cmap="Blues", interpolation="nearest")
    ax.set_xticks(range(len(col_labels)))
    ax.set_xticklabels(col_labels, rotation=30, ha="right", fontsize=7.5)
    ax.set_yticks(range(len(row_labels)))
    ax.set_yticklabels(row_labels, fontsize=7.5)
    ax.set_title(title, fontsize=9.5, fontweight="bold", pad=4)
    for i in range(matrix.shape[0]):
        for j in range(matrix.shape[1]):
            ax.text(j, i, f"{matrix[i,j]:.2f}", ha="center", va="center",
                    fontsize=6, color="black" if matrix[i, j] < 0.4 else "white")
    return im


def _draw_composition_bar(ax, neg: np.ndarray, zero: np.ndarray, pos: np.ndarray,
                           x_labels: List[str], title: str):
    """Stacked bar: % -1, % 0, % +1 per entry."""
    x = np.arange(len(x_labels))
    bw = 0.65
    ax.bar(x, neg  * 100, bw, label="w = -1", color=_PALETTE["neg"],  edgecolor="white", lw=0.5)
    ax.bar(x, zero * 100, bw, label="w = 0",  color=_PALETTE["zero"], edgecolor="white", lw=0.5,
           bottom=neg * 100)
    ax.bar(x, pos  * 100, bw, label="w = +1", color=_PALETTE["pos"],  edgecolor="white", lw=0.5,
           bottom=(neg + zero) * 100)
    ax.set_xticks(x)
    ax.set_xticklabels(x_labels, rotation=40, ha="right", fontsize=7.5)
    ax.set_ylabel("Weight fraction (%)", fontsize=9)
    ax.set_title(title, fontsize=9.5, fontweight="bold", pad=4)
    ax.set_ylim(0, 100)
    ax.legend(fontsize=7, loc="upper right", framealpha=0.85)


# ---------------------------------------------------------------------------
# Main
# ---------------------------------------------------------------------------

def generate(save_dir: Optional[Path] = None, model=None) -> Path:
    """
    Generate Figure 2 and save it.

    Parameters
    ----------
    save_dir : Path, optional
        Output directory.  Defaults to plots/paper_figures/.
    model : EmberNetVLM, optional
        Live model for real weight extraction.

    Returns
    -------
    Path : path to the saved PNG.
    """
    if save_dir is None:
        save_dir = Path("plots/paper_figures")
    save_dir.mkdir(parents=True, exist_ok=True)

    if model is None:
        skip_no_data("fig2_ternary_stats")
        return save_dir / "fig2_ternary_stats.png"

    stats = _extract_stats_from_model(model)
    if stats is None:
        skip_no_data("fig2_ternary_stats (extraction failed)")
        return save_dir / "fig2_ternary_stats.png"

    num_layers = len(stats["attention_stats"])
    layer_labels = [f"L{i}" for i in range(num_layers)]

    # ------------------------------------------------------------------ #
    # Build per-layer average zero fraction for attention and shared expert
    # ------------------------------------------------------------------ #
    attn_projs  = ["q_proj", "k_proj", "v_proj", "o_proj"]
    shared_projs = ["gate_proj", "up_proj", "down_proj"]

    attn_matrix   = _zero_fraction_matrix(stats["attention_stats"], attn_projs)
    shared_matrix = _zero_fraction_matrix(stats["shared_stats"],    shared_projs)

    # Per-layer mean expert sparsity (averaged over all 8 experts per layer)
    expert_zero = np.zeros((num_layers, 8))
    for i, layer_exps in enumerate(stats["expert_stats"]):
        for e, exp_s in enumerate(layer_exps):
            expert_zero[i, e] = np.mean([exp_s[p]["zero"] for p in shared_projs if p in exp_s])

    # Per-layer mean neg/zero/pos for stacked bar (all BitLinear in decoder, aggregated)
    neg_per_layer  = np.zeros(num_layers)
    zero_per_layer = np.zeros(num_layers)
    pos_per_layer  = np.zeros(num_layers)
    for i in range(num_layers):
        vals: List[Dict] = []
        for pk in attn_projs:
            vals.append(stats["attention_stats"][i][pk])
        for e in range(8 if len(stats["expert_stats"][i]) == 8 else len(stats["expert_stats"][i])):
            for pk in shared_projs:
                vals.append(stats["expert_stats"][i][e].get(pk, {"neg":0,"zero":0,"pos":0}))
        for pk in shared_projs:
            vals.append(stats["shared_stats"][i].get(pk, {"neg":0,"zero":0,"pos":0}))
        neg_per_layer[i]  = np.mean([v["neg"]  for v in vals])
        zero_per_layer[i] = np.mean([v["zero"] for v in vals])
        pos_per_layer[i]  = np.mean([v["pos"]  for v in vals])

    # ------------------------------------------------------------------ #
    # Figure layout
    # ------------------------------------------------------------------ #
    fig = plt.figure(figsize=(18, 11), dpi=VIZ_CONFIG["dpi"])
    gs  = gridspec.GridSpec(2, 3, hspace=0.55, wspace=0.40)

    ax_attn_heat   = fig.add_subplot(gs[0, 0])
    ax_shared_heat = fig.add_subplot(gs[0, 1])
    ax_expert_heat = fig.add_subplot(gs[0, 2])
    ax_comp_bar    = fig.add_subplot(gs[1, :])

    # Panel A — attention sparsity heatmap
    im_a = _draw_sparsity_heatmap(
        ax_attn_heat, attn_matrix, layer_labels, attn_projs,
        "A) Attention Projection Sparsity\n(zero weight fraction per layer)"
    )
    plt.colorbar(im_a, ax=ax_attn_heat, fraction=0.046, pad=0.04, label="Zero frac.")

    # Panel B — shared expert sparsity heatmap
    im_b = _draw_sparsity_heatmap(
        ax_shared_heat, shared_matrix, layer_labels, shared_projs,
        "B) Shared Expert (VA hook) Sparsity"
    )
    plt.colorbar(im_b, ax=ax_shared_heat, fraction=0.046, pad=0.04, label="Zero frac.")

    # Panel C — expert-averaged sparsity heatmap (layers × experts)
    expert_short = [f"E{i}" for i in range(8)]
    im_c = ax_expert_heat.imshow(expert_zero, aspect="auto", vmin=0.0, vmax=0.7,
                                  cmap="YlOrRd", interpolation="nearest")
    ax_expert_heat.set_xticks(range(8))
    ax_expert_heat.set_xticklabels(expert_short, fontsize=8)
    ax_expert_heat.set_yticks(range(num_layers))
    ax_expert_heat.set_yticklabels(layer_labels, fontsize=7)
    ax_expert_heat.set_title("C) Domain Expert Sparsity Heatmap\n(avg zero fraction, layers × experts)", fontsize=9.5, fontweight="bold")
    plt.colorbar(im_c, ax=ax_expert_heat, fraction=0.046, pad=0.04, label="Zero frac.")

    # Panel D — stacked composition bar per layer
    _draw_composition_bar(
        ax_comp_bar,
        neg_per_layer, zero_per_layer, pos_per_layer,
        layer_labels,
        "D) Average Ternary Weight Composition per Decoder Layer (all BitLinear modules aggregated)"
    )
    ax_comp_bar.axhline(y=100/3, color="gray", lw=1, ls="--", alpha=0.5,
                         label="Uniform 33.3% each")
    ax_comp_bar.legend(fontsize=7.5, loc="upper right", framealpha=0.85)

    fig.suptitle(
        "Figure 2 — Ternary Weight Distribution Across EmberNet BitLinear Layers",
        fontsize=12, fontweight="bold", y=1.01
    )

    out_path = save_dir / "fig2_ternary_stats.pdf"
    fig.savefig(out_path, bbox_inches="tight")
    out_png = save_dir / "fig2_ternary_stats.png"
    fig.savefig(out_png, bbox_inches="tight")
    plt.close(fig)
    print(f"[fig2] Saved → {out_png}")
    return out_png


if __name__ == "__main__":
    generate()
