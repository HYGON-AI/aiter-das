# SPDX-License-Identifier: MIT
# Copyright (C) 2024-2026, Advanced Micro Devices, Inc. All rights reserved.
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
 
import torch
from torch import Tensor
from typing import Optional
import functools
from pathlib import Path
import pandas as pd
from ..jit.core import (
    compile_ops,
    AITER_META_DIR,
)
from ..utility import dtypes
from ..jit.utils.chip_info import get_cu_num


@compile_ops("module_gemm_a8w8", fc_name="gemm_a8w8")
def gemm_a8w8(
    XQ: torch.Tensor,
    WQ: torch.Tensor,
    x_scale: torch.Tensor,
    w_scale: torch.Tensor,
    Out: torch.Tensor,
    bias: Optional[torch.Tensor] = None,
    splitK: int = 0,
) -> torch.Tensor: ...


@compile_ops("module_gemm_a8w8_asm", fc_name="gemm_a8w8_asm")
def gemm_a8w8_asm(
    XQ: Tensor,  # A:[M, K] i8
    WQ: Tensor,  # B:[N, K] i8 -> shuffle layout(32,16)
    x_scale: Tensor,  # A_scale:[M, 1] f32
    w_scale: Tensor,  # B_scale:[1, N] f32
    Out: Tensor,  # Out:[M, N] bf16
    bias: Tensor,  # bias:[1, N] f32
    sub_m: Optional[int] = 128,
    sub_n: Optional[int] = 128,
    pad_a: Optional[int] = 0,
    pad_b: Optional[int] = 0,
    pad_c: Optional[int] = 0,
    splitK: Optional[int] = 0,
) -> torch.Tensor: ...


@compile_ops("module_gemm_a8w8_blockscale", fc_name="gemm_a8w8_blockscale")
def _gemm_a8w8_blockscale(
    XQ: Tensor,
    WQ: Tensor,
    x_scale: Tensor,
    w_scale: Tensor,
    out: Tensor,
) -> torch.Tensor: ...


def _check_w8a8_inputs(XQ, WQ, x_scale, w_scale, dtype):
    if XQ.ndim != 2 or WQ.ndim != 2 or XQ.shape[1] != WQ.shape[1]:
        raise ValueError("W8A8 expects A[M,K] and B[N,K]")
    if XQ.shape[1] <= 0 or WQ.shape[0] <= 0:
        raise ValueError("W8A8 requires positive N and K")
    if XQ.dtype != WQ.dtype or XQ.dtype not in (torch.int8, torch.float8_e4m3fn):
        raise ValueError("W8A8 inputs must have matching INT8 or FP8 E4M3FN dtype")
    if dtype not in (torch.float16, torch.bfloat16):
        raise ValueError("W8A8 output must be FP16 or BF16")
    for tensor in (XQ, WQ, x_scale, w_scale):
        if not tensor.is_cuda or tensor.device != XQ.device:
            raise ValueError("W8A8 tensors must be on the same HIP device")
        if not tensor.is_contiguous():
            raise ValueError("W8A8 tensors must be contiguous")
    if x_scale.dtype != w_scale.dtype:
        raise ValueError("W8A8 scales must have matching dtype")


def gemm_a8w8_blockscale(XQ, WQ, x_scale, w_scale, out=None, *, dtype=None):
    """CK FP8 GEMM: FP32 scales use (1,128)/(128,128) blocks.

    E8M0 scales (native dtype or uint8 storage) use (1,32)/(32,32) blocks.

    Accepts either the existing output-buffer form or framework ``dtype=`` form.
    """
    dtype = dtype if dtype is not None else (out.dtype if out is not None else dtypes.bf16)
    _check_w8a8_inputs(XQ, WQ, x_scale, w_scale, dtype)
    if XQ.dtype != torch.float8_e4m3fn:
        raise ValueError("blockscale requires FP8 E4M3FN inputs")
    m, k = XQ.shape
    n = WQ.shape[0]
    if x_scale.dtype == torch.float32:
        group = 128
    elif x_scale.dtype == torch.uint8 or str(x_scale.dtype) == "torch.float8_e8m0fnu":
        group = 32
        x_scale, w_scale = x_scale.view(torch.uint8), w_scale.view(torch.uint8)
    else:
        raise ValueError("blockscale requires FP32 or E8M0 scales")
    if tuple(x_scale.shape) != (m, (k + group - 1) // group) or tuple(w_scale.shape) != ((n + group - 1) // group, (k + group - 1) // group):
        raise ValueError(f"blockscale expects scales [M,ceil(K/{group})] and [ceil(N/{group}),ceil(K/{group})]")
    if out is None:
        out = torch.empty((m, n), device=XQ.device, dtype=dtype)
    if out.shape != (m, n) or out.dtype != dtype or out.device != XQ.device or not out.is_contiguous():
        raise ValueError("out must be contiguous [M,N] on the input device with the requested dtype")
    if m == 0:
        return out
    return _gemm_a8w8_blockscale(XQ, WQ, x_scale, w_scale, out)


@compile_ops("module_gemm_a8w8_blockscale_asm", fc_name="flatmm_a8w8_blockscale_asm")
def flatmm_a8w8_blockscale_asm(
    XQ: Tensor,
    WQ: Tensor,
    x_scale: Tensor,
    w_scale: Tensor,
    out: Tensor,
) -> torch.Tensor: ...


@functools.lru_cache(maxsize=1024)
def compute_gemm_SplitK(M: int, N: int, K: int, tile_m: int, tile_n: int, tile_k: int):
    cu_num = get_cu_num()
    tile_num = ((M + tile_m - 1) // tile_m) * ((N + tile_n - 1) // tile_n)
    cusPerTile = cu_num / tile_num
    splitK = 0
    while cusPerTile >= pow(2, splitK + 1) and (pow(2, splitK + 1) * tile_k) < 2 * K:
        splitK += 1
    return splitK


@functools.lru_cache(maxsize=1024)
def get_CKGEMM_config(
    M: int,
    N: int,
    K: int,
):
    if not hasattr(get_CKGEMM_config, "ckgemm_dict"):
        path = Path(AITER_META_DIR) / "aiter/configs/a8w8_tuned_gemm.csv"
        if not path.is_file():
            get_CKGEMM_config.ckgemm_dict = {}
            return None
        ckgemm_dict = pd.read_csv(
            path
        ).drop_duplicates()
        get_CKGEMM_config.ckgemm_dict = ckgemm_dict.set_index(["M", "N", "K"]).to_dict(
            "index"
        )
    config = get_CKGEMM_config.ckgemm_dict.get((M, N, K), None)
    if config != None:
        mnk = config["kernelName"].split("_")[2].split("x")[1:]
        config["tile_m"] = int(mnk[0])
        config["tile_n"] = int(mnk[1])
        config["tile_k"] = int(mnk[2])
    return config


@functools.lru_cache(maxsize=1024)
def get_ASMGEMM_config(M: int, N: int, K: int, bias: bool, dtype: torch.dtype):
    if not hasattr(get_ASMGEMM_config, "asmgemm_dict"):
        asmGemmDictDf = pd.read_csv(
            f"{AITER_META_DIR}/aiter/configs/asm_a8w8_gemm.csv"
        ).drop_duplicates()
        asmGemmDictDf.bias = asmGemmDictDf.bias.apply(
            lambda s: True if s in ["True", 1, "true"] else False
        )
        get_ASMGEMM_config.asmgemm_dict = asmGemmDictDf.set_index(
            ["M", "N", "K", "bias", "outdtype"]
        ).to_dict("index")
    return get_ASMGEMM_config.asmgemm_dict.get((M, N, K, bias, str(dtype)), None)


def gemm_a8w8_ASM(
    XQ: Tensor,
    WQ: Tensor,
    x_scale: Tensor,
    w_scale: Tensor,
    bias: Tensor,
    dtype=dtypes.bf16,
    check=False,
):
    """
    Notes for use gemm_a8w8_ASM:
    1. WQ(weight) must be shuffle, you can use \
        'weightshuffle = shuffle_weight(weight,layout=(32,16))'
    2. Use asm gemm must give bias, if not have bias, please give  \
        'bias=torch.zeros(n,dtype=dtypes.fp32,device='cuda')'
    """
    if check:
        assert dtype in [
            dtypes.bf16,
        ], f"Output {dtype=} is currently not supported in gemm_a8w8_ASM"
        assert (
            x_scale.dtype == dtypes.fp32 and w_scale.dtype == dtypes.fp32
        ), f"{x_scale.dtype=} or {w_scale.dtype=} must be dtypes.fp32"
    m = XQ.shape[0]
    n = WQ.shape[0]
    k = XQ.shape[-1]
    if (
        x_scale.dtype == dtypes.fp32
        and w_scale.dtype == dtypes.fp32
        and (asm_config := get_ASMGEMM_config(m, n, k, bias != None, dtype)) != None
    ):
        assert (
            bias != None
        ), "Use asm gemm must give bias, please give a \
            bias=torch.zeros(n,dtype=dtypes.fp32,device='cuda')"
        splitK = asm_config["splitK"]
        Y = torch.empty(m, n, dtype=dtype, device=XQ.device)
        return gemm_a8w8_asm(XQ, WQ, x_scale, w_scale, Y, bias, splitK=splitK)
    return None


def gemm_a8w8_CK(
    XQ: Tensor,
    WQ: Tensor,
    x_scale: Tensor,
    w_scale: Tensor,
    bias: Optional[Tensor] = None,
    dtype=dtypes.bf16,
    splitK: Optional[int] = None,
):
    _check_w8a8_inputs(XQ, WQ, x_scale, w_scale, dtype)
    m = XQ.shape[0]
    n = WQ.shape[0]
    k = XQ.shape[-1]
    if x_scale.numel() != m or w_scale.numel() != n:
        raise ValueError("rowwise scales must contain M and N elements")
    if x_scale.dtype not in (torch.float32, dtype):
        raise ValueError("rowwise scales must be FP32 or match the output dtype")
    if bias is not None and (bias.numel() != n or bias.dtype != dtype or bias.device != XQ.device or not bias.is_contiguous()):
        raise ValueError("bias must contain N contiguous elements and match output dtype/device")
    if splitK is not None and (not isinstance(splitK, int) or splitK < 0 or splitK > 16):
        raise ValueError("splitK must be an integer exponent from 0 to 16")
    if m == 0:
        return torch.empty((m, n), dtype=dtype, device=XQ.device)
    # The HCU baseline uses native 16x16 MMAC instances, independently of AMD
    # tuning CSVs. Splitting into low-precision atomic outputs is not supported.
    if splitK is None:
        splitK = 0
    Y = torch.empty(m, n, dtype=dtype, device=XQ.device)
    return gemm_a8w8(XQ, WQ, x_scale, w_scale, Y, bias, splitK)


def gemm_a8w8_blockscale_CK(
    XQ: Tensor, WQ: Tensor, x_scale: Tensor, w_scale: Tensor, dtype=dtypes.bf16
):
    assert dtype in [
        dtypes.bf16,
        dtypes.fp16,
    ], f"Output {dtype=} is currently not supported in gemm_a8w8"
    m = XQ.shape[0]
    n = WQ.shape[0]
    k = XQ.shape[-1]
    Y = torch.empty(m, n, dtype=dtype, device=XQ.device)
    return gemm_a8w8_blockscale(XQ, WQ, x_scale, w_scale, Y)


def flatmm_a8w8_blockscale_ASM(
    XQ: Tensor,
    WQ: Tensor,
    x_scale: Tensor,
    w_scale: Tensor,
    dtype=dtypes.fp16,
):
    assert dtype in [
        dtypes.fp16,
    ], f"Output {dtype=} is currently not supported in gemm_a8w8"
    m = XQ.shape[0]
    n = WQ.shape[0]
    k = XQ.shape[-1]
    Y = torch.empty(m, n, dtype=dtype, device=XQ.device)
    return flatmm_a8w8_blockscale_asm(XQ, WQ, x_scale, w_scale, Y)


@compile_ops("module_gemm_a8w8_tune", fc_name="gemm_a8w8_tune")
def gemm_a8w8_tune(
    XQ: Tensor,
    WQ: Tensor,
    x_scale: Tensor,
    w_scale: Tensor,
    out: Tensor,
    kernelId: int,
    splitK: int = 0,
) -> torch.Tensor: ...


@compile_ops("module_gemm_a8w8_blockscale_tune", fc_name="gemm_a8w8_blockscale_tune")
def gemm_a8w8_blockscale_tune(
    XQ: Tensor,
    WQ: Tensor,
    x_scale: Tensor,
    w_scale: Tensor,
    out: Tensor,
    kernelId: int,
    splitK: int = 0,
) -> torch.Tensor: ...
