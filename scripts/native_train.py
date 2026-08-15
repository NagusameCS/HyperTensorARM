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
Native Geodesic Training Loop (Paper XII gap 2)

Implements the NativeLinear architecture training from scratch:
  W_native = B C B^T  with B on the Stiefel manifold, C as learned core.

Includes KExpansion scheduler, RiemannianAdamW with QR retraction,
and comparison against standard full-rank training at matched compute.

Reference: Stewart, "Native Geodesic Training," HyperTensor Paper XII, 2026.

Usage:
    python scripts/native_train.py --model smollm2-135m --k 128 --steps 5000
    python scripts/native_train.py --model qwen-1.5b --k 256 --kexpansion
"""

import torch
import torch.nn as nn
import torch.optim as optim
import numpy as np
import time
import argparse
from typing import Optional, Tuple, List, Dict
from dataclasses import dataclass, field


# ---------------------------------------------------------------------------
# NativeLinear: W = B C B^T where B is on the Stiefel manifold
# ---------------------------------------------------------------------------

class NativeLinear(nn.Module):
    """
    Compressed linear layer: W_native = B C B^T.

    Parameters:
        d_in, d_out: Input/output dimensions.
        k: Subspace dimension (rank).
        B: Orthonormal basis B ∈ R^{d_out × k} on St(k, d_out).
        C: Core transformation C ∈ R^{k × k}.
    """

    def __init__(self, d_in: int, d_out: int, k: int, bias: bool = False):
        super().__init__()
        self.d_in = d_in
        self.d_out = d_out
        self.k = k

        # Initialize B orthonormal via random + QR
        B0 = torch.randn(d_out, k)
        Q, _ = torch.linalg.qr(B0)
        self.B = nn.Parameter(Q)

        # Core C initialized as identity scaled
        self.C = nn.Parameter(torch.eye(k) * 0.1)

        if bias:
            self.bias = nn.Parameter(torch.zeros(d_out))
        else:
            self.bias = None

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        # x: (..., d_in)
        # W_native = B @ C @ B^T, but we project x first for efficiency
        Bt_x = x @ self.B  # (..., k)
        C_Bt_x = Bt_x @ self.C.T  # (..., k)
        out = C_Bt_x @ self.B.T  # (..., d_out)
        if self.bias is not None:
            out = out + self.bias
        return out

    def effective_weight(self) -> torch.Tensor:
        """Return the full-rank effective weight W = B C B^T."""
        return self.B @ self.C @ self.B.T

    def parameter_count(self) -> int:
        return self.k * self.d_out + self.k * self.k + (self.d_out if self.bias is not None else 0)

    def compression_ratio(self) -> float:
        full = self.d_in * self.d_out
        return self.parameter_count() / full

    def qr_retract(self):
        """Project B back onto the Stiefel manifold via QR."""
        with torch.no_grad():
            Q, _ = torch.linalg.qr(self.B.data)
            self.B.data = Q


# ---------------------------------------------------------------------------
# KExpansion Scheduler
# ---------------------------------------------------------------------------

class KExpansionScheduler:
    """
    Automatically grows subspace dimension k when training plateaus.

    Algorithm (Paper XII, Appendix B):
      1. Start at k_init.
      2. Train for patience steps.
      3. If loss stagnates, expand k by k_step.
      4. New basis columns: random orthonormal, Gram-Schmidt orthogonalized.
      5. Repeat until k_max.
    """

    def __init__(
        self,
        k_init: int = 32,
        k_step: int = 32,
        k_max: int = 512,
        patience: int = 200,
        threshold: float = 1e-4,
    ):
        self.k_init = k_init
        self.k_step = k_step
        self.k_max = k_max
        self.patience = patience
        self.threshold = threshold
        self.current_k = k_init
        self.best_loss = float('inf')
        self.steps_since_improvement = 0

    def should_expand(self, current_loss: float) -> bool:
        """Check if k should be expanded."""
        if current_loss < self.best_loss - self.threshold:
            self.best_loss = current_loss
            self.steps_since_improvement = 0
            return False
        else:
            self.steps_since_improvement += 1
            return (self.steps_since_improvement >= self.patience and
                    self.current_k < self.k_max)

    def expand(self, layer: NativeLinear) -> int:
        """Expand layer from current_k to current_k + k_step."""
        k_old = self.current_k
        k_new = min(self.current_k + self.k_step, self.k_max)

        with torch.no_grad():
            # Create new B with more columns
            B_new = torch.randn(layer.d_out, k_new)
            B_new[:, :k_old] = layer.B.data  # Preserve old basis

            # Gram-Schmidt orthogonalize new columns
            for j in range(k_old, k_new):
                for i in range(j):
                    B_new[:, j] -= (B_new[:, i] @ B_new[:, j]) * B_new[:, i]
                B_new[:, j] /= max(B_new[:, j].norm(), 1e-10)

            # Expand C
            C_new = torch.zeros(k_new, k_new)
            C_new[:k_old, :k_old] = layer.C.data

            # Initialize new blocks small-random
            C_new[k_old:, :k_old] = torch.randn(k_new - k_old, k_old) * 0.01
            C_new[:k_old, k_old:] = torch.randn(k_old, k_new - k_old) * 0.01

            # Update layer
            layer.k = k_new
            layer.B = nn.Parameter(B_new)
            layer.C = nn.Parameter(C_new)

        self.current_k = k_new
        self.steps_since_improvement = 0
        return k_new


# ---------------------------------------------------------------------------
# RiemannianAdamW
# ---------------------------------------------------------------------------

class RiemannianAdamW(optim.Optimizer):
    """
    AdamW with QR retraction after each step for Stiefel-constrained parameters.

    Only parameters named 'B' are retracted. Other parameters use standard AdamW.
    """

    def __init__(self, params, lr=1e-3, betas=(0.9, 0.999), weight_decay=0.01):
        defaults = dict(lr=lr, betas=betas, weight_decay=weight_decay)
        super().__init__(params, defaults)

    @torch.no_grad()
    def step(self, closure=None):
        loss = None
        if closure is not None:
            loss = closure()

        for group in self.param_groups:
            for p in group['params']:
                if p.grad is None:
                    continue

                grad = p.grad
                state = self.state[p]

                # State init
                if len(state) == 0:
                    state['step'] = 0
                    state['exp_avg'] = torch.zeros_like(p)
                    state['exp_avg_sq'] = torch.zeros_like(p)

                exp_avg, exp_avg_sq = state['exp_avg'], state['exp_avg_sq']
                beta1, beta2 = group['betas']

                state['step'] += 1
                t = state['step']

                # Decay
                exp_avg.mul_(beta1).add_(grad, alpha=1 - beta1)
                exp_avg_sq.mul_(beta2).addcmul_(grad, grad, value=1 - beta2)

                # Bias correction
                bias1 = 1 - beta1 ** t
                bias2 = 1 - beta2 ** t
                step_size = group['lr'] / bias1

                # Update
                denom = exp_avg_sq.sqrt().div_(bias2 ** 0.5).add_(1e-8)
                p.addcdiv_(exp_avg, denom, value=-step_size)

                # Weight decay
                if group['weight_decay'] > 0:
                    p.mul_(1 - group['lr'] * group['weight_decay'])

        return loss


# ---------------------------------------------------------------------------
# Training loop
# ---------------------------------------------------------------------------

@dataclass
class TrainConfig:
    """Training configuration."""
    k_init: int = 128
    k_max: int = 1024
    use_kexpansion: bool = True
    kexpansion_patience: int = 200
    kexpansion_step: int = 64
    lr: float = 1e-3
    weight_decay: float = 0.01
    steps: int = 5000
    log_interval: int = 100
    qr_interval: int = 10  # QR retraction every N steps
    target_matrix: Optional[torch.Tensor] = None  # For reconstruction task


def train_native_linear(
    layer: NativeLinear,
    target: torch.Tensor,
    config: TrainConfig,
) -> Dict:
    """
    Train a NativeLinear layer to approximate a target weight matrix.

    Args:
        layer: NativeLinear instance.
        target: Target weight matrix W ∈ R^{d_out × d_in}.
        config: Training configuration.

    Returns:
        Dict with training metrics.
    """
    optimizer = RiemannianAdamW(
        [layer.B, layer.C],
        lr=config.lr,
        weight_decay=config.weight_decay,
    )
    scheduler = KExpansionScheduler(
        k_init=config.k_init,
        k_step=config.kexpansion_step,
        k_max=config.k_max,
        patience=config.kexpansion_patience,
    ) if config.use_kexpansion else None

    loss_history = []
    k_history = [layer.k]
    best_loss = float('inf')
    best_state = None

    target_norm = target.norm().item() ** 2

    for step in range(config.steps):
        # Forward
        W_native = layer.effective_weight()
        loss = ((W_native - target) ** 2).sum() / max(target_norm, 1e-10)

        # Backward
        optimizer.zero_grad()
        loss.backward()
        optimizer.step()

        # QR retraction
        if step % config.qr_interval == 0:
            layer.qr_retract()

        loss_val = loss.item()
        loss_history.append(loss_val)

        if loss_val < best_loss:
            best_loss = loss_val
            best_state = {
                'B': layer.B.data.clone(),
                'C': layer.C.data.clone(),
                'k': layer.k,
                'step': step,
            }

        # KExpansion
        if scheduler is not None and scheduler.should_expand(loss_val):
            k_new = scheduler.expand(layer)
            k_history.append(k_new)
            # Reinitialize optimizer for new parameter shape
            optimizer = RiemannianAdamW(
                [layer.B, layer.C],
                lr=config.lr * 0.5,  # Reduce LR on expansion
                weight_decay=config.weight_decay,
            )

        if step % config.log_interval == 0:
            print(f"  step {step:5d}: loss={loss_val:.6f}, k={layer.k}")

    return {
        'loss_history': loss_history,
        'k_history': k_history,
        'final_loss': loss_history[-1],
        'best_loss': best_loss,
        'best_step': best_state['step'] if best_state else -1,
        'final_k': layer.k,
        'compression_ratio': layer.compression_ratio(),
        'best_state': best_state,
    }


# ---------------------------------------------------------------------------
# Comparison: Native vs Full-Rank vs LoRA
# ---------------------------------------------------------------------------

def compare_methods(
    d: int = 512,
    k_native: int = 128,
    lora_rank: int = 8,
    steps: int = 1000,
) -> Dict:
    """
    Compare NativeLinear vs full-rank vs LoRA at matched parameter count.

    Returns metrics for all three methods.
    """
    # Generate synthetic target with power-law spectrum
    rng = np.random.default_rng(42)
    U, _ = np.linalg.qr(rng.normal(0, 1, (d, d)))
    V, _ = np.linalg.qr(rng.normal(0, 1, (d, d)))
    S = np.diag(np.sort(rng.exponential(1, d))[::-1])  # Power-law decay
    W_target = torch.tensor(U @ S @ V.T, dtype=torch.float32)

    results = {}

    # 1. NativeLinear
    layer = NativeLinear(d, d, k_native)
    cfg = TrainConfig(k_init=k_native, use_kexpansion=False, steps=steps,
                      log_interval=steps//5, qr_interval=5)
    start = time.perf_counter()
    native_result = train_native_linear(layer, W_target, cfg)
    native_result['wall_time'] = time.perf_counter() - start
    native_result['param_count'] = layer.parameter_count()
    results['native'] = native_result

    # 2. Full-rank (LoRA-style: W = W_init + A B)
    W_init = torch.randn(d, d) * 0.01
    A = nn.Parameter(torch.randn(d, lora_rank) * 0.01)
    B = nn.Parameter(torch.randn(lora_rank, d) * 0.01)
    opt = optim.AdamW([A, B], lr=1e-3)
    lora_losses = []
    start = time.perf_counter()
    for step in range(steps):
        W_lora = W_init + A @ B
        loss = ((W_lora - W_target) ** 2).sum() / (W_target.norm().item() ** 2 + 1e-10)
        opt.zero_grad()
        loss.backward()
        opt.step()
        lora_losses.append(loss.item())
    results['lora'] = {
        'loss_history': lora_losses,
        'final_loss': lora_losses[-1],
        'wall_time': time.perf_counter() - start,
        'param_count': 2 * d * lora_rank,
    }

    # 3. Full-rank training of a small matrix for reference
    W_full = nn.Parameter(torch.randn(d, d) * 0.01)
    opt = optim.AdamW([W_full], lr=1e-3)
    full_losses = []
    start = time.perf_counter()
    for step in range(steps):
        loss = ((W_full - W_target) ** 2).sum() / (W_target.norm().item() ** 2 + 1e-10)
        opt.zero_grad()
        loss.backward()
        opt.step()
        full_losses.append(loss.item())
    results['full_rank'] = {
        'loss_history': full_losses,
        'final_loss': full_losses[-1],
        'wall_time': time.perf_counter() - start,
        'param_count': d * d,
    }

    return results


# ---------------------------------------------------------------------------
# CLI
# ---------------------------------------------------------------------------
if __name__ == "__main__":
    parser = argparse.ArgumentParser(description='Native Geodesic Training')
    parser.add_argument('--d', type=int, default=512, help='Matrix dimension')
    parser.add_argument('--k', type=int, default=128, help='Native rank')
    parser.add_argument('--steps', type=int, default=1000, help='Training steps')
    parser.add_argument('--compare', action='store_true', help='Run comparison')
    parser.add_argument('--kexpansion', action='store_true', help='Use KExpansion')
    args = parser.parse_args()

    print("=" * 60)
    print("Native Geodesic Training")
    print("=" * 60)

    if args.compare:
        print(f"\nComparing Native(k={args.k}) vs LoRA(r=8) vs Full-Rank at d={args.d}")
        results = compare_methods(d=args.d, k_native=args.k, steps=args.steps)

        for method, r in results.items():
            print(f"\n  {method}:")
            print(f"    Final loss:     {r['final_loss']:.6f}")
            print(f"    Wall time:      {r['wall_time']:.2f}s")
            print(f"    Parameters:     {r['param_count']}")
            if 'compression_ratio' in r:
                print(f"    Compression:    {r['compression_ratio']*100:.1f}%")
    else:
        # Single NativeLinear training
        rng = np.random.default_rng(42)
        U, _ = np.linalg.qr(rng.normal(0, 1, (args.d, args.d)))
        S = np.diag(np.sort(rng.exponential(1, args.d))[::-1])
        W_target = torch.tensor(U @ S, dtype=torch.float32)

        layer = NativeLinear(args.d, args.d, args.k)
        cfg = TrainConfig(
            k_init=args.k,
            use_kexpansion=args.kexpansion,
            steps=args.steps,
            log_interval=args.steps // 10,
            qr_interval=5,
        )
        result = train_native_linear(layer, W_target, cfg)
        print(f"\n  Final loss: {result['final_loss']:.6f}")
        print(f"  Final k:    {result['final_k']}")
        print(f"  Best loss:  {result['best_loss']:.6f} (step {result['best_step']})")
        print(f"  Compression ratio: {result['compression_ratio']*100:.1f}%")

    print("\n  Native Train module: OK")
