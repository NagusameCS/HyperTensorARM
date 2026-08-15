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

"""HyperRetro CPU optimized backend — AVX2 fused dual Q8 GEMV.

Loads the compiled ``hyperretro_cpu_avx2.so`` (or .dll) via ctypes.
If the library is not available, falls back to the torch/numpy backends.

The AVX2 kernel shares the input vector load between two Q8_0 dot
products, giving ~16% DRAM traffic reduction vs separate GEMVs plus
the SIMD speedup from 8-wide FMA operations.
"""
from __future__ import annotations

import ctypes
import os
import sys
from pathlib import Path
from typing import Tuple

import numpy as np

_HERE = Path(__file__).resolve().parent
_IS_ARM = os.uname().machine in ("arm64", "aarch64") if hasattr(os, "uname") else False
# On Apple Silicon / ARM64 load the NEON build (same exported symbols).
_LIB_NAME = "hyperretro_cpu_neon" if _IS_ARM else "hyperretro_cpu_avx2"
_LIB = None


def _find_lib() -> str | None:
    """Find the compiled CPU library."""
    names = [_LIB_NAME]
    if _IS_ARM:
        names.append("hyperretro_cpu_avx2")  # allow the AVX2-named fallback build
    # Check common locations
    candidates = []
    for name in names:
        candidates += [
            _HERE / "csrc" / "cpu" / f"{name}.so",
            _HERE / "csrc" / "cpu" / f"{name}.dll",
            _HERE / "csrc" / "cpu" / f"{name}.dylib",
            # Build directory
            Path("build") / "cpu" / f"{name}.so",
            Path("build") / "cpu" / f"{name}.dll",
            Path("build") / "cpu" / f"{name}.dylib",
        ]
    for path in candidates:
        if path.exists():
            return str(path)
    return None


def _load_lib():
    """Load the CPU AVX2 library. Returns None if not available."""
    global _LIB
    if _LIB is not None:
        return _LIB

    lib_path = _find_lib()
    if lib_path is None:
        return None

    try:
        _LIB = ctypes.CDLL(lib_path)
    except OSError:
        return None

    # Set function signatures
    _LIB.gemv_dual_q8_0_avx2.argtypes = [
        ctypes.POINTER(ctypes.c_float),  # x
        ctypes.c_int,                     # in_dim
        ctypes.POINTER(ctypes.c_float),  # scales_a
        ctypes.POINTER(ctypes.c_int8),   # codes_a
        ctypes.c_int,                     # rows
        ctypes.POINTER(ctypes.c_float),  # scales_b
        ctypes.POINTER(ctypes.c_int8),   # codes_b
        ctypes.POINTER(ctypes.c_float),  # out_a
        ctypes.POINTER(ctypes.c_float),  # out_b
    ]
    _LIB.gemv_dual_q8_0_avx2.restype = None

    # Optional scalar fallback
    try:
        _LIB.gemv_dual_q8_0_scalar.argtypes = _LIB.gemv_dual_q8_0_avx2.argtypes
        _LIB.gemv_dual_q8_0_scalar.restype = None
    except Exception:
        pass

    # Optional fast path (SDOT on ARM / fast AVX2 on x86)
    try:
        _LIB.gemv_dual_q8_0_avx2_fast.argtypes = _LIB.gemv_dual_q8_0_avx2.argtypes
        _LIB.gemv_dual_q8_0_avx2_fast.restype = None
    except Exception:
        pass

    return _LIB


def _has_cpu_opt() -> bool:
    return _load_lib() is not None


def _gemv_dual_q8_cpu_opt(
    x: np.ndarray,
    W_a: Tuple[np.ndarray, np.ndarray],
    W_b: Tuple[np.ndarray, np.ndarray],
) -> Tuple[np.ndarray, np.ndarray]:
    """Fused dual Q8 GEMV via compiled AVX2 kernel."""
    lib = _load_lib()
    if lib is None:
        raise RuntimeError("CPU AVX2 library not available")

    from hyperretro.kernels import _as_q8_pair

    x = np.ascontiguousarray(x, dtype=np.float32)
    sa, ca = _as_q8_pair(W_a)
    sb, cb = _as_q8_pair(W_b)

    rows_a, n_blocks_a, _ = ca.shape
    rows_b, n_blocks_b, _ = cb.shape
    assert rows_a == rows_b, "W_a and W_b must have same number of rows"
    assert n_blocks_a == n_blocks_b, "W_a and W_b must have same number of blocks"

    in_dim = n_blocks_a * 32
    assert x.size == in_dim, f"x size {x.size} != in_dim {in_dim}"

    rows = rows_a
    out_a = np.empty(rows, dtype=np.float32)
    out_b = np.empty(rows, dtype=np.float32)

    x_ptr = x.ctypes.data_as(ctypes.POINTER(ctypes.c_float))
    sa_ptr = np.ascontiguousarray(sa, dtype=np.float32).ctypes.data_as(ctypes.POINTER(ctypes.c_float))
    ca_ptr = np.ascontiguousarray(ca, dtype=np.int8).ctypes.data_as(ctypes.POINTER(ctypes.c_int8))
    sb_ptr = np.ascontiguousarray(sb, dtype=np.float32).ctypes.data_as(ctypes.POINTER(ctypes.c_float))
    cb_ptr = np.ascontiguousarray(cb, dtype=np.int8).ctypes.data_as(ctypes.POINTER(ctypes.c_int8))
    oa_ptr = out_a.ctypes.data_as(ctypes.POINTER(ctypes.c_float))
    ob_ptr = out_b.ctypes.data_as(ctypes.POINTER(ctypes.c_float))

    # Try AVX2 first, fall back to scalar
    try:
        lib.gemv_dual_q8_0_avx2(
            x_ptr, in_dim, sa_ptr, ca_ptr, rows,
            sb_ptr, cb_ptr, oa_ptr, ob_ptr,
        )
    except Exception:
        lib.gemv_dual_q8_0_scalar(
            x_ptr, in_dim, sa_ptr, ca_ptr, rows,
            sb_ptr, cb_ptr, oa_ptr, ob_ptr,
        )

    return out_a, out_b


def _gemv_dual_q8_cpu_opt_fast(
    x: np.ndarray,
    W_a: Tuple[np.ndarray, np.ndarray],
    W_b: Tuple[np.ndarray, np.ndarray],
) -> Tuple[np.ndarray, np.ndarray]:
    """Fused dual Q8 GEMV via the compiled fast path (NEON SDOT)."""
    lib = _load_lib()
    if lib is None:
        raise RuntimeError("CPU library not available")
    if not hasattr(lib, "gemv_dual_q8_0_avx2_fast"):
        # No fast symbol: use the exact kernel.
        return _gemv_dual_q8_cpu_opt(x, W_a, W_b)

    from hyperretro.kernels import _as_q8_pair

    x = np.ascontiguousarray(x, dtype=np.float32)
    sa, ca = _as_q8_pair(W_a)
    sb, cb = _as_q8_pair(W_b)

    rows_a, n_blocks_a, _ = ca.shape
    rows_b, n_blocks_b, _ = cb.shape
    assert rows_a == rows_b, "W_a and W_b must have same number of rows"
    assert n_blocks_a == n_blocks_b, "W_a and W_b must have same number of blocks"

    in_dim = n_blocks_a * 32
    assert x.size == in_dim, f"x size {x.size} != in_dim {in_dim}"

    rows = rows_a
    out_a = np.empty(rows, dtype=np.float32)
    out_b = np.empty(rows, dtype=np.float32)

    x_ptr = x.ctypes.data_as(ctypes.POINTER(ctypes.c_float))
    sa_ptr = np.ascontiguousarray(sa, dtype=np.float32).ctypes.data_as(ctypes.POINTER(ctypes.c_float))
    ca_ptr = np.ascontiguousarray(ca, dtype=np.int8).ctypes.data_as(ctypes.POINTER(ctypes.c_int8))
    sb_ptr = np.ascontiguousarray(sb, dtype=np.float32).ctypes.data_as(ctypes.POINTER(ctypes.c_float))
    cb_ptr = np.ascontiguousarray(cb, dtype=np.int8).ctypes.data_as(ctypes.POINTER(ctypes.c_int8))
    oa_ptr = out_a.ctypes.data_as(ctypes.POINTER(ctypes.c_float))
    ob_ptr = out_b.ctypes.data_as(ctypes.POINTER(ctypes.c_float))

    lib.gemv_dual_q8_0_avx2_fast(
        x_ptr, in_dim, sa_ptr, ca_ptr, rows,
        sb_ptr, cb_ptr, oa_ptr, ob_ptr,
    )
    return out_a, out_b


def _bench_cpu_opt(dim: int = 4096, iters: int = 50) -> dict:
    """Quick benchmark of the CPU optimised kernel."""
    from hyperretro.kernels import q8_0_quantize
    import time

    x = np.random.randn(dim).astype(np.float32)
    W_a = np.random.randn(dim, dim).astype(np.float32) * 0.02
    W_b = np.random.randn(dim, dim).astype(np.float32) * 0.02
    sa, ca = q8_0_quantize(W_a)
    sb, cb = q8_0_quantize(W_b)

    # Warmup
    for _ in range(5):
        _gemv_dual_q8_cpu_opt(x, (sa, ca), (sb, cb))

    t0 = time.perf_counter()
    for _ in range(iters):
        _gemv_dual_q8_cpu_opt(x, (sa, ca), (sb, cb))
    elapsed = (time.perf_counter() - t0) / iters * 1000

    return {"dim": dim, "iters": iters, "median_ms": elapsed}
