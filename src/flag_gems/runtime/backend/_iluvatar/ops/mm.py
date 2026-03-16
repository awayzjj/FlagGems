"""
Iluvatar backend mm: same interface as flag_gems.ops.mm, kernel from triton.ops.matmul._kernel.
"""
import logging

import torch
import triton
import triton.language as tl

from flag_gems.runtime import torch_device_fn
from triton.ops.matmul import _kernel as triton_mm_kernel

logger = logging.getLogger(__name__)

_ordered_datatypes = [torch.float16, torch.bfloat16, torch.float32]


def get_higher_dtype(a, b):
    if a is b:
        return a
    assert a in _ordered_datatypes
    assert b in _ordered_datatypes
    for d in _ordered_datatypes:
        if a is d:
            return b
        if b is d:
            return a
    raise AssertionError("unreachable")


def _to_tl_type(ty):
    return getattr(tl, str(ty).split(".")[-1])


def _launch_mm(a, b, c, M, N, K):
    """Launch Triton matmul _kernel; c must be pre-allocated."""
    ab_dtype = get_higher_dtype(a.dtype, b.dtype)
    acc_dtype_tl = tl.float32
    ab_dtype_tl = _to_tl_type(ab_dtype)

    grid = lambda META: (
        triton.cdiv(M, META["BLOCK_M"]) * triton.cdiv(N, META["BLOCK_N"]),
        META["SPLIT_K"],
    )

    with torch_device_fn.device(a.device):
        triton_mm_kernel[grid](
            a,
            b,
            c,
            M,
            N,
            K,
            a.stride(0),
            a.stride(1),
            b.stride(0),
            b.stride(1),
            c.stride(0),
            c.stride(1),
            acc_dtype=acc_dtype_tl,
            input_precision=None,
            fp8_fast_accum=True,
            GROUP_M=8,
            AB_DTYPE=ab_dtype_tl,
        )
    return c


def mm(a, b):
    logger.debug("ILUVATAR GEMS MM")
    device = a.device
    if a.stride(0) > 1 and a.stride(1) > 1:
        a = a.contiguous()
    if b.stride(0) > 1 and b.stride(1) > 1:
        b = b.contiguous()
    assert a.shape[1] == b.shape[0], "incompatible dimensions"
    M, K = a.shape
    _, N = b.shape
    c_dtype = get_higher_dtype(a.dtype, b.dtype)
    c = torch.empty((M, N), device=device, dtype=c_dtype)
    return _launch_mm(a, b, c, M, N, K)


def mm_out(a, b, *, out):
    logger.debug("ILUVATAR GEMS MM_OUT")
    if a.stride(0) > 1 and a.stride(1) > 1:
        a = a.contiguous()
    if b.stride(0) > 1 and b.stride(1) > 1:
        b = b.contiguous()
    assert a.shape[1] == b.shape[0], "incompatible dimensions"
    M, K = a.shape
    _, N = b.shape
    return _launch_mm(a, b, out, M, N, K)
