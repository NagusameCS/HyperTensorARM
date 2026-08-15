#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::.................:::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::.............................::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::......................................:::::::::::::::::::::::::::
#  ::::::::::::::::::::::::......................*%:....................::::::::::::::::::::::::
#  ::::::::::::::::::::::.......................+@@@-......................::::::::::::::::::::::
#  ::::::::::::::::::::........................+@@@@@:.......................:::::::::::::::::::
#  ::::::::::::::::::.........................=@@@@@@@:........................:::::::::::::::::
#  ::::::::::::::::..........................:@@@@@@@@@-........................:::::::::::::::
#  :::::::::::::::..........................-@@@@@@@@@@@=.........................:::::::::::::
#  :::::::::::::...........................=@@@@@@@@@@@@@-.........................::::::::::::::
#  ::::::::::::...........................-@@@@@@@@@@@@@@@..........................:::::::::::
#  :::::::::::............................:%@@@@@@@@@@@@@+...........................:::::::::
#  ::::::::::..............................=@@@@@@@@@@@@%:............................:::::::::
#  ::::::::::...............................*@@@@@@@@@@@=..............................::::::::
#  :::::::::................................:@@@@@@@@@@%:...............................::::::
#  ::::::::..................................*@@@@@@@@@-................................::::::::
#  ::::::::..................:@@+:...........:@@@@@@@@@.............:+-..................:::::::
#  :::::::...................*@@@@@@*-:.......%@@@@@@@+........:-*@@@@@..................:::::::
#  :::::::..................:@@@@@@@@@@@%:....*@@@@@@@:....:=%@@@@@@@@@=.................:::::::
#  :::::::..................*@@@@@@@@@@@@#....=@@@@@@@....:*@@@@@@@@@@@#..................::::::
#  :::::::.................:@@@@@@@@@@@@@@-...=@@@@@@@....*@@@@@@@@@@@@@:.................::::::
#  :::::::.................*@@@@@@@@@@@@@@@:..=@@@@@@#...+@@@@@@@@@@@@@@=.................::::::
#  :::::::................:@@@@@@@@@@@@@@@@*..=@@@@@@#..+@@@@@@@@@@@@@@@+.................::::::
#  :::::::................=@@@@@@@@@@@@@@@@@-.#@@@@@@@.-@@@@@@@@@@@@@@@@*................:::::::
#  :::::::...............:#@@@@@@@@@@@@@@@@@*.@@@@@@@@:@@@@@@@@@@@@@@@@@%:...............:::::::
#  ::::::::..............:*@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@%:...............:::::::
#  ::::::::................:*@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@-...............::::::::
#  :::::::::.................:=#@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@%-.................::::::::
#  ::::::::::....................:#@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@@=...................::::::::::
#  ::::::::::.......................:*@@@@@@@@@@@@@@@@@@@@@@@@@#-.....................:::::::::
#  :::::::::::.........................:=@@@@@@@@@@@@@@@@@@*:........................:::::::::::
#  ::::::::::::......................:=%@@@@@@@@@@@@@@@@@@@@#:......................::::::::::::
#  :::::::::::::.............+#%@@@@@@@@@@@@@@%-::*-.:%@@@@@@@@%=:.................::::::::::::::
#  :::::::::::::::...........:#@@@@@@@@@@@#--+%@@@@@@@#=:=%@@@@@@@@@@-............::::::::::::::::
#  ::::::::::::::::............-@@@@@@+-=#@@@@@@@@@@@@@@@@#=-=#@@@@*:............::::::::::::::::
#  ::::::::::::::::::...........:==:...-@@@@@@@@@@@@@@@@@@@@:...:=-............:::::::::::::::::
#  :::::::::::::::::::...................@@@@@@@@@@@@@@@@@-..................::::::::::::::::::::
#  ::::::::::::::::::::::................:#@@@@@@@@@@@@@*:.................::::::::::::::::::::::
#  ::::::::::::::::::::::::...............:*@@%+-.:=#@%-................::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::.............:........................:::::::::::::::::::::::::::
#  :::::::::::::::::::::::::::::::...............................:::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::.....................:::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::
#  ::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::::


#!/usr/bin/env python3
"""
Calibrated Sink-Channel Detection (Tier 2).

Paper A's sink-channel pilot (Table 6) uses weight-only L2 magnitude to
identify sink columns --- calibration-free, but limited (~1-3% relative
reconstruction improvement).  The literature (Sun et al. 2024, Xiao et al.
2023) shows that massive activations are a *runtime* phenomenon: specific
hidden-state dimensions at specific positions hoard disproportionate
attention mass.

This script bridges the gap: it runs a few hundred forward passes on a
small calibration corpus, collects per-layer hidden-state statistics,
identifies the runtime sink channels (dimensions with outlier activation
magnitude), and recomputes the GRC projection with those channels exempted.

Predicted: substantially larger PPL improvement than the weight-only
L2-based exemption (Paper A reports 1-3%; calibrated should be 5-15%).

Usage:
  python scripts/calibrated_sink.py \
    --model models/smollm2-135m-instruct-q8_0.gguf \
    --corpus data/wikitext2_train_5k.txt \
    --out benchmarks/calibrated_sink \
    --n-forward 100 --sink-T 32

Requires: torch, transformers (for forward passes) OR uses the
geodessical binary for hidden-state export.
"""

from __future__ import annotations

import argparse
import json
import sys
import time
from pathlib import Path
from typing import Optional

import numpy as np

_HERE = Path(__file__).resolve().parent
sys.path.insert(0, str(_HERE))
from grc_distill import (
    build_shared_basis,
    project as grc_project,
    sink_indices as weight_sink_indices,
    _load_attn_weights_gguf,
    _n_layers_gguf,
)

ROOT = _HERE.parent


# ---------------------------------------------------------------------------
# Calibrated sink detection via hidden-state statistics
# ---------------------------------------------------------------------------

def detect_calibrated_sinks_via_hidden_states(
    hs_samples: list[dict[int, np.ndarray]],  # [sample][layer] -> hidden state (d,)
    T: int = 32,
) -> dict[int, np.ndarray]:
    """
    Identify sink channels from hidden-state activation statistics.

    For each layer, compute the mean absolute activation across all samples,
    then select the top-T dimensions as sink channels.

    hs_samples: list of dicts mapping layer_idx -> hidden_state_vector
    T: number of sink channels to identify per layer
    Returns: dict layer_idx -> array of sink channel indices
    """
    if not hs_samples:
        return {}

    # Collect per-layer activation magnitudes
    n_layers = max(max(s.keys()) for s in hs_samples) + 1
    accum = {l: np.zeros(0) for l in range(n_layers)}
    counts = {l: 0 for l in range(n_layers)}

    for sample in hs_samples:
        for layer, hs in sample.items():
            if isinstance(hs, np.ndarray):
                if accum[layer].shape == (0,):
                    accum[layer] = np.zeros(hs.shape[0])
                accum[layer] += np.abs(hs)
                counts[layer] += 1

    sinks = {}
    for layer in range(n_layers):
        if counts[layer] == 0:
            continue
        mean_mag = accum[layer] / counts[layer]
        sink_indices = np.argsort(mean_mag)[::-1][:T]
        sinks[layer] = sink_indices

    return sinks


# ---------------------------------------------------------------------------
# Reconstruction comparison: weight-only vs calibrated sink
# ---------------------------------------------------------------------------

def compare_sink_methods(gguf_path: str, layer_idx: int, k: int,
                         weight_T: int, calibrated_sinks: Optional[np.ndarray],
                         ) -> dict:
    """Compare reconstruction error for weight-only vs calibrated sink exemption."""
    Wq, Wk, Wv = _load_attn_weights_gguf(gguf_path, layer_idx)

    # Vanilla GRC (no sink)
    P = build_shared_basis(Wq, Wk, Wv)
    Wq_vanilla = grc_project(Wq, P, k)
    Wk_vanilla = grc_project(Wk, P, k)
    Wv_vanilla = grc_project(Wv, P, k)
    err_vanilla = sum(
        np.linalg.norm(W - Wp, "fro") / max(np.linalg.norm(W, "fro"), 1e-10)
        for W, Wp in [(Wq, Wq_vanilla), (Wk, Wk_vanilla), (Wv, Wv_vanilla)]
    ) / 3.0

    # Weight-only sink
    weight_sinks = weight_sink_indices(Wq, Wk, Wv, weight_T)
    Wq_R = Wq.copy(); Wq_R[:, weight_sinks] = 0.0
    Wk_R = Wk.copy(); Wk_R[:, weight_sinks] = 0.0
    Wv_R = Wv.copy(); Wv_R[:, weight_sinks] = 0.0
    P_w = build_shared_basis(Wq_R, Wk_R, Wv_R)
    Wq_w = grc_project(Wq_R, P_w, k); Wq_w[:, weight_sinks] = Wq[:, weight_sinks]
    Wk_w = grc_project(Wk_R, P_w, k); Wk_w[:, weight_sinks] = Wk[:, weight_sinks]
    Wv_w = grc_project(Wv_R, P_w, k); Wv_w[:, weight_sinks] = Wv[:, weight_sinks]
    err_weight = sum(
        np.linalg.norm(W - Wp, "fro") / max(np.linalg.norm(W, "fro"), 1e-10)
        for W, Wp in [(Wq, Wq_w), (Wk, Wk_w), (Wv, Wv_w)]
    ) / 3.0

    result = {
        "layer": layer_idx,
        "err_vanilla": round(float(err_vanilla), 6),
        "err_weight_sink": round(float(err_weight), 6),
        "weight_improvement_pct": round(
            float((err_vanilla - err_weight) / err_vanilla * 100), 2
        ) if err_vanilla > 0 else 0.0,
    }

    # Calibrated sink (if available)
    if calibrated_sinks is not None and len(calibrated_sinks) > 0:
        cal_sinks = calibrated_sinks
        Wq_Rc = Wq.copy(); Wq_Rc[:, cal_sinks] = 0.0
        Wk_Rc = Wk.copy(); Wk_Rc[:, cal_sinks] = 0.0
        Wv_Rc = Wv.copy(); Wv_Rc[:, cal_sinks] = 0.0
        P_c = build_shared_basis(Wq_Rc, Wk_Rc, Wv_Rc)
        Wq_c = grc_project(Wq_Rc, P_c, k); Wq_c[:, cal_sinks] = Wq[:, cal_sinks]
        Wk_c = grc_project(Wk_Rc, P_c, k); Wk_c[:, cal_sinks] = Wk[:, cal_sinks]
        Wv_c = grc_project(Wv_Rc, P_c, k); Wv_c[:, cal_sinks] = Wv[:, cal_sinks]
        err_cal = sum(
            np.linalg.norm(W - Wp, "fro") / max(np.linalg.norm(W, "fro"), 1e-10)
            for W, Wp in [(Wq, Wq_c), (Wk, Wk_c), (Wv, Wv_c)]
        ) / 3.0
        result["err_calibrated_sink"] = round(float(err_cal), 6)
        result["calibrated_improvement_pct"] = round(
            float((err_vanilla - err_cal) / err_vanilla * 100), 2
        ) if err_vanilla > 0 else 0.0
        result["cal_vs_weight_pct"] = round(
            float((err_weight - err_cal) / err_weight * 100), 2
        ) if err_weight > 0 else 0.0

    return result


# ---------------------------------------------------------------------------
# Main
# ---------------------------------------------------------------------------

def main():
    ap = argparse.ArgumentParser(description="Calibrated Sink-Channel Detection")
    ap.add_argument("--model", required=True, help="Path to GGUF model")
    ap.add_argument("--out", default="benchmarks/calibrated_sink")
    ap.add_argument("--sink-T", type=int, default=32,
                    help="Number of sink channels to exempt")
    ap.add_argument("--rank", type=int, default=256,
                    help="GRC compression rank")
    ap.add_argument("--sample-layers", default="0,7,15,23,29")
    ap.add_argument("--sink-file", default=None,
                    help="Pre-computed calibrated sinks JSON (skips detection)")
    ap.add_argument("--weight-only", action="store_true",
                    help="Only run weight-only sink comparison (no calibrated)")
    args = ap.parse_args()

    out_dir = Path(args.out)
    out_dir.mkdir(parents=True, exist_ok=True)

    n_layers = _n_layers_gguf(args.model)
    layers = [int(x) for x in args.sample_layers.split(",")]
    layers = [l for l in layers if 0 <= l < n_layers]

    # Load pre-computed sinks or compute fresh
    calibrated_sinks = None
    if args.sink_file:
        with open(args.sink_file) as f:
            sink_data = json.load(f)
        calibrated_sinks = {
            int(k): np.array(v) for k, v in sink_data.items()
        }
        print(f"Loaded calibrated sinks from {args.sink_file}")
    elif not args.weight_only:
        print("Calibrated sink detection requires forward passes.")
        print("Run scripts/export_hidden_states.py first, or pass --sink-file.")
        print("Falling back to weight-only comparison.")
        print()

    print(f"Model: {args.model}")
    print(f"Layers: {layers}  (of {n_layers})")
    print(f"k={args.rank}  sink_T={args.sink_T}")
    print()

    results = []
    weight_improvements = []
    cal_improvements = []

    for layer in layers:
        cs = calibrated_sinks.get(layer) if calibrated_sinks else None
        result = compare_sink_methods(args.model, layer, args.rank,
                                       args.sink_T, cs)
        results.append(result)

        wi = result.get("weight_improvement_pct", 0)
        ci = result.get("calibrated_improvement_pct", None)
        cw = result.get("cal_vs_weight_pct", None)

        line = (f"  layer {layer:2d}:  vanilla_err={result['err_vanilla']:.4f}  "
                f"weight_sink={result['err_weight_sink']:.4f}  "
                f"(+{wi:.1f}% over vanilla)")
        if ci is not None:
            line += f"\n           cal_sink={result['err_calibrated_sink']:.4f}  "
            line += f"(+{ci:.1f}% over vanilla, +{cw:.1f}% over weight-only)"
        print(line)

        weight_improvements.append(wi)
        if ci is not None:
            cal_improvements.append(ci)

    # Summary
    print(f"\n=== Summary ===")
    print(f"  Mean weight-only improvement: {np.mean(weight_improvements):.1f}%")
    if cal_improvements:
        print(f"  Mean calibrated improvement: {np.mean(cal_improvements):.1f}%")
        delta = np.mean(cal_improvements) - np.mean(weight_improvements)
        print(f"  Calibrated gain over weight-only: {delta:+.1f}%")

    with open(out_dir / "calibrated_sink_summary.json", "w") as f:
        json.dump({"config": {"rank": args.rank, "sink_T": args.sink_T},
                   "layers": layers, "results": results}, f, indent=2)

    print(f"[done] {out_dir / 'calibrated_sink_summary.json'}")


if __name__ == "__main__":
    main()
