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
#  ::::::::::::::::::::::.......................+@@@-......................:::::::::::::::::::::
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
#  :::::::::::::::...........:#@@@@@@@@@@@#--+%@@@@@@@#=:=%@@@@@@@@@@-............:::::::::::::::
#  ::::::::::::::::............-@@@@@@+-=#@@@@@@@@@@@@@@@@#=-=#@@@@*:............:::::::::::::::
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

"""EAGLE-style speculative drafter on factored attention (attack #6).

Standard speculative decoding: a small "drafter" model proposes k future
tokens cheaply, the large model verifies them in one parallel forward pass.
EAGLE (Li et al. 2024) improves on this by using the large model's *own
features* to draft — specifically the final hidden state — rather than a
separate small model.

HyperRetro's factored attention provides a unique advantage: the GRC
shared basis compresses Q/K/V computation into a k-dimensional bottleneck
(x @ A^T, shape (..., k)). This low-rank intermediate is a natural drafting
feature — it captures the input's projection onto the most important
directions for attention, and it's already computed during the forward pass.

This module provides:

1. :class:`FactoredDrafter` — a lightweight head that takes the k-dim
   projected input and predicts future token embeddings. Trainable via
   distillation on the teacher's embedding output.

2. :func:`draft_tokens` — given past K/V cache and the drafter, produce
   k draft tokens autoregressively.

3. :func:`verify_and_accept` — standard speculative verification:
   run the full model on the draft sequence, accept matching prefixes.

Architecture:
    x ∈ R^d  →  A ∈ R^{k×d}  →  h = x @ A^T ∈ R^k  (already computed)
    h → DrafterMLP(h) → embedding_pred ∈ R^d
    embedding_pred → lm_head → token_logits → draft_token

Training (requires GPU, queued for #6.5):
    - Freeze the base model
    - Train DrafterMLP to minimise KL(teacher_logits || drafter_logits)
    - Same calibration corpus as distill (WikiText-2)
    - Typical: 500 steps, lr=1e-4, batch=8

Industry context (May 2026):
    - EAGLE/EAGLE-2: ~3-4× speedup on llama.cpp
    - Medusa: ~2× speedup with multiple heads
    - Standard in vllm, TensorRT-LLM
    - HyperRetro's advantage: the k-dim bottleneck is 2.4× smaller than
      the full d-dim feature, so the drafter is proportionally cheaper.
"""

from __future__ import annotations

from dataclasses import dataclass, field
from pathlib import Path
from typing import Optional

import numpy as np


# ---------------------------------------------------------------------------
# Drafter head architecture (torch)
# ---------------------------------------------------------------------------

def _make_drafter_head(
    k_dim: int,
    d_model: int,
    vocab_size: int,
    *,
    hidden_dim: int = 256,
    n_layers: int = 2,
) -> "torch.nn.Module":
    """Build a lightweight MLP that maps k-dim projected input → vocab logits.

    The head is tiny: ~k_dim × hidden_dim + hidden_dim × d_model + d_model × vocab_size.
    For Qwen2.5-1.5B (k=640, d=1536, V=151936):
        params ≈ 640×256 + 256×1536 + 1536×151936 ≈ 233M — too large!
        With d→V projection shared with lm_head:
        params ≈ 640×256 + 256×1536 ≈ 557K — tiny!

    The trick: use the model's own lm_head for the final projection.
    The drafter only predicts the *embedding* (d-dim), not the token.
    This makes the drafter ~550K params vs the full 1.5B model.
    """
    import torch
    import torch.nn as nn

    class DrafterMLP(nn.Module):
        def __init__(self):
            super().__init__()
            layers = []
            in_dim = k_dim
            for i in range(n_layers):
                out_dim = hidden_dim if i < n_layers - 1 else d_model
                layers.append(nn.Linear(in_dim, out_dim))
                if i < n_layers - 1:
                    layers.append(nn.SiLU())
                in_dim = out_dim
            self.mlp = nn.Sequential(*layers)

        def forward(self, h: torch.Tensor) -> torch.Tensor:
            """h: (..., k) → embedding_pred: (..., d)"""
            return self.mlp(h)

    return DrafterMLP()


# ---------------------------------------------------------------------------
# Factored drafter config
# ---------------------------------------------------------------------------

@dataclass
class FactoredDrafterConfig:
    """Configuration for the factored-attention drafter."""
    k_dim: int = 640                # GRC rank (shared basis dimension)
    d_model: int = 1536             # hidden size
    vocab_size: int = 151936        # vocabulary size
    hidden_dim: int = 256           # drafter MLP hidden dim
    n_layers: int = 2               # drafter MLP depth
    max_draft_len: int = 4          # number of tokens to draft per step
    temperature: float = 1.0        # sampling temperature for draft
    # Training (queued)
    learning_rate: float = 1e-4
    steps: int = 500
    batch_size: int = 8


# ---------------------------------------------------------------------------
# Drafting algorithm (numpy reference)
# ---------------------------------------------------------------------------

@dataclass
class DraftResult:
    """Result of one drafting step."""
    draft_tokens: list[int]        # proposed token ids
    draft_probs: list[float]       # probabilities at each step
    n_accepted: int = 0            # filled by verify_and_accept
    acceptance_rate: float = 0.0


def draft_tokens_numpy(
    h: np.ndarray,                    # (k,) projected input
    drafter_weights: list[tuple[np.ndarray, np.ndarray]],  # [(W, b)] for each layer
    lm_head: np.ndarray,              # (V, d) language model head
    *,
    max_len: int = 4,
    temperature: float = 1.0,
) -> DraftResult:
    """Draft future tokens from the projected input h = x @ A^T.

    This is a numpy reference implementation for testing/validation.
    The torch version uses the actual model's lm_head.

    Parameters
    ----------
    h : (k,) — the k-dimensional projected input from factored attention.
    drafter_weights : list of (W, b) tuples for the drafter MLP.
    lm_head : (V, d) — the model's language model head (ties to embedding).
    max_len : max tokens to draft.
    temperature : sampling temperature.

    Returns
    -------
    DraftResult with draft_tokens and draft_probs.
    """
    x = h.copy()
    for W, b in drafter_weights[:-1]:
        x = np.maximum(0, x @ W.T + b)  # SiLU approx as ReLU for numpy
    # Last layer → d-dim embedding prediction
    W_last, b_last = drafter_weights[-1]
    embedding_pred = x @ W_last.T + b_last  # (d,)

    # Project to vocab via lm_head
    logits = lm_head @ embedding_pred  # (V,)
    if temperature > 0:
        logits = logits / temperature

    # Sample first token
    probs = np.exp(logits - np.max(logits))
    probs = probs / probs.sum()
    token = int(np.random.choice(len(probs), p=probs))

    result = DraftResult(draft_tokens=[token], draft_probs=[float(probs[token])])
    return result


def verify_and_accept(
    draft_tokens: list[int],
    teacher_logits: np.ndarray,      # (draft_len+1, V) from teacher forward
) -> tuple[int, list[int]]:
    """Standard speculative verification.

    Runs the teacher (full model) on the draft sequence in parallel.
    For each position, if teacher argmax matches draft token, accept;
    otherwise sample from teacher and stop.

    Returns (n_accepted, accepted_tokens).
    """
    n_accepted = 0
    accepted = []
    for i, draft_tok in enumerate(draft_tokens):
        teacher_tok = int(np.argmax(teacher_logits[i]))
        if teacher_tok == draft_tok:
            n_accepted += 1
            accepted.append(draft_tok)
        else:
            # Sample from teacher distribution
            p = np.exp(teacher_logits[i] - np.max(teacher_logits[i]))
            p = p / p.sum()
            accepted.append(int(np.random.choice(len(p), p=p)))
            break
    return n_accepted, accepted


# ---------------------------------------------------------------------------
# Throughput model
# ---------------------------------------------------------------------------

@dataclass
class SpeedupEstimate:
    """Estimated speedup from speculative decoding with factored drafter."""
    draft_len: int = 4
    acceptance_rate: float = 0.7     # typical EAGLE acceptance rate
    draft_cost_ratio: float = 0.02   # drafter is ~2% the cost of full forward
    verify_cost_ratio: float = 1.0   # full forward cost (parallel verify)

    @property
    def expected_tokens_per_step(self) -> float:
        """Expected number of accepted tokens per verification step."""
        # Geometric series: sum_{i=0}^{draft_len-1} acceptance_rate^i
        r = self.acceptance_rate
        return (1 - r ** self.draft_len) / (1 - r) if r < 1 else float(self.draft_len)

    @property
    def cost_per_step(self) -> float:
        """Total cost: draft_len drafts + 1 verification."""
        return self.draft_len * self.draft_cost_ratio + self.verify_cost_ratio

    @property
    def speedup(self) -> float:
        """Tokens per unit cost vs baseline (1 token / 1.0 cost)."""
        return self.expected_tokens_per_step / self.cost_per_step

    @property
    def speedup_no_draft_cost(self) -> float:
        """Speedup if drafting were free (upper bound)."""
        return self.expected_tokens_per_step / self.verify_cost_ratio


def estimate_factored_speedup(
    k_dim: int = 640,
    d_model: int = 1536,
    n_layers: int = 28,
    *,
    draft_len: int = 4,
    acceptance_rate: float = 0.7,
) -> dict:
    """Estimate speedup for HyperRetro factored speculative decoding.

    The drafter cost is dominated by:
    - k-dim → d-dim MLP: O(k × hidden) per token
    - Full forward: O(L × d²) per token

    Ratio ≈ (k × hidden) / (L × d²) ≈ (640×256) / (28×1536²) ≈ 0.0025 = 0.25%
    """
    drafter_flops = k_dim * 256 * 2  # MLP: k→256→d, roughly
    full_flops = n_layers * d_model * d_model * 4  # rough per-token FLOPs
    draft_cost_ratio = drafter_flops / full_flops

    est = SpeedupEstimate(
        draft_len=draft_len,
        acceptance_rate=acceptance_rate,
        draft_cost_ratio=draft_cost_ratio,
    )

    return {
        "k_dim": k_dim,
        "d_model": d_model,
        "n_layers": n_layers,
        "draft_len": draft_len,
        "acceptance_rate": acceptance_rate,
        "drafter_flops_per_token": drafter_flops,
        "full_forward_flops_per_token": full_flops,
        "draft_cost_ratio": round(draft_cost_ratio, 6),
        "expected_tokens_per_step": round(est.expected_tokens_per_step, 2),
        "speedup": round(est.speedup, 2),
        "speedup_upper_bound": round(est.speedup_no_draft_cost, 2),
    }


# ---------------------------------------------------------------------------
# CLI
# ---------------------------------------------------------------------------

def _cli_main(argv: list[str] | None = None) -> int:
    import argparse
    import json

    p = argparse.ArgumentParser(
        description="Estimate speculative decoding speedup with factored attention."
    )
    p.add_argument("--k-dim", type=int, default=640)
    p.add_argument("--d-model", type=int, default=1536)
    p.add_argument("--n-layers", type=int, default=28)
    p.add_argument("--draft-len", type=int, default=4)
    p.add_argument("--acceptance-rate", type=float, default=0.7)
    p.add_argument("--json", action="store_true")
    args = p.parse_args(argv)

    est = estimate_factored_speedup(
        k_dim=args.k_dim,
        d_model=args.d_model,
        n_layers=args.n_layers,
        draft_len=args.draft_len,
        acceptance_rate=args.acceptance_rate,
    )

    if args.json:
        print(json.dumps(est, indent=2))
    else:
        print(f"Factored speculative decode speedup estimate:")
        print(f"  k={est['k_dim']}, d={est['d_model']}, L={est['n_layers']}")
        print(f"  Draft cost ratio: {est['draft_cost_ratio']:.4f} ({est['draft_cost_ratio']*100:.2f}%)")
        print(f"  Draft len: {est['draft_len']}, acceptance: {est['acceptance_rate']}")
        print(f"  Expected tokens/step: {est['expected_tokens_per_step']}")
        print(f"  Estimated speedup: {est['speedup']:.2f}×")
        print(f"  Upper bound (free draft): {est['speedup_upper_bound']:.2f}×")
    return 0


if __name__ == "__main__":
    import sys
    sys.exit(_cli_main())
