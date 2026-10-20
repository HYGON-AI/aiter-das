# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: MIT
"""aiter blockwise_scaled_cast_transpose 标准 CLI 测试。

被测算子：aiter.blockwise_scaled_cast_transpose（1x128 行块量化 + cast + transpose，
单调用双布局双 scale 输出；block_len 仅 128、block_scaling_dim 仅 1）。

CLI 用法：
    python test_blockwise_scaled_cast_transpose.py --list-cases
    python test_blockwise_scaled_cast_transpose.py                     # default 组
    python test_blockwise_scaled_cast_transpose.py --case ragged:3
    python test_blockwise_scaled_cast_transpose.py --case all --bench-only
    python test_blockwise_scaled_cast_transpose.py --case dtype:99    # 越界 -> error 退出

运行前提（与 aiter/op_tests/test_fused_metadata.py 同）：`import aiter` 必须解析到
本源码树（PYTHONPATH=<repo>/aiter 或先 rebuild 出 .so），否则会加载到不含本算子的
旧 site-packages 副本。

口径（与 aiter/op_tests/test_fused_metadata.py 一致）：
  - 正确性：公开 API aiter.blockwise_scaled_cast_transpose（经 @compile_ops 桩），
    对拍基准 BlockwiseQuantizerReference（纯 torch），断言严格度 atol=0, rtol=0；
    GEMM_READY 的 scale padding 掩码逻辑见 _verify_correctness。
  - 计时：直调 module_blockwise_scaling pybind 绑定（绕过 torch.ops/compile_ops
    wrapper，消除框架开销）；CUDA-event 计时，warmup 不计时（覆盖首次 JIT/上下文
    初始化），iters 按 batch=10 分组取每组均值，对样本取中位数。
  - ref 列 = 纯 torch 参考量化的同口径计时（上下文参考）。

case 组（详见 --list-cases）：
  default  基准配置（2048x2000 fp32->int8 COMPACT 双输出）。
  dtype    输入/输出 dtype 矩阵 3x3（2048x2048 GEMM_READY 双输出）。
  layout   GEMM_READY/COMPACT x 双输出/仅rowwise x pow2 T/F（bf16->e4m3）。
  ragged   非对齐 shape 矩阵（K/M 不整除分块，走非对齐慢路径）。
  size     bench 主力矩阵（bf16->e4m3 GEMM_READY 双输出 + fp32->int8 COMPACT 代表点）。
  columnwise_only  仅 columnwise 输出（rowwise 侧传 None 的正向组合）。
  exc      异常契约组 6 条（校验入口报错行为；--bench-only 自动 skip）。

字段约定：case 的 N 为输入 dim-1 长度（量化 K 维）；compact 即 all_gather_usage=True
（COMPACT scale 布局）；return_transpose=False 即仅 rowwise（output_t/scale_inv_t
传 None、columnwise=False 路径）；columnwise_only=True 为仅 columnwise（rowwise 侧
传 None）。
"""

import argparse
import functools
import math
import os
import sys
import dataclasses
from typing import Optional, Tuple, Iterable

import torch
from torch.utils.cpp_extension import IS_HIP_EXTENSION

import aiter

# 源码树根（包含 aiter 包的那一级目录）：<repo>/aiter/op_tests/test_*.py -> <repo>/aiter
# `import aiter` 必须解析到这里（与 test_fused_metadata.py 同约定）。
_SRC_PARENT = os.path.dirname(os.path.dirname(os.path.abspath(__file__)))


@functools.lru_cache(maxsize=1)
def _get_aiter_fn():
    """返回 module_blockwise_scaling 的原始 pybind 绑定（绕过 @compile_ops wrapper），
    计时直调该绑定，消除框架 wrapper 开销。"""
    from aiter.jit.core import get_module

    try:
        md = get_module("module_blockwise_scaling")
    except Exception:
        if not hasattr(aiter, "blockwise_scaled_cast_transpose"):
            raise RuntimeError(
                f"`import aiter` loaded a copy without "
                f"blockwise_scaled_cast_transpose: "
                f"{getattr(aiter, '__file__', '???')!r}. "
                f"Run against the source tree instead:\n"
                f"    PYTHONPATH={_SRC_PARENT} python "
                f"{os.path.abspath(__file__)} [args]"
            ) from None
        # 尚未构建：先用公开 wrapper 触发一次 JIT 编译（首次调用会 build_module），
        # 再取绑定。warm-up 调用严格复用 default case 几何（2048x2000 fp32->int8
        # COMPACT 双输出 pow2）与 get_scale_shape 的 scale 形状，
        # 保证缓冲区尺寸与正式 case 完全一致（避免 undersized scale 缓冲）。
        _wm, _wn = 2048, 2000
        aiter.blockwise_scaled_cast_transpose(
            torch.randn((_wm, _wn), dtype=torch.float32, device="cuda"),
            torch.empty((_wm, _wn), dtype=torch.uint8, device="cuda"),
            torch.empty(get_scale_shape((_wm, _wn), columnwise=False, all_gather_usage=True),
                        dtype=torch.float32, device="cuda"),
            torch.empty((_wm, _wn), dtype=torch.uint8, device="cuda"),
            torch.empty(get_scale_shape((_wm, _wn), columnwise=True, all_gather_usage=True),
                        dtype=torch.float32, device="cuda"),
            blockwise_fp8_block_len, block_scaling_dim, True, True,
            0.0, True, True, torch.int8,
        )
        md = get_module("module_blockwise_scaling")
    return md.blockwise_scaled_cast_transpose


blockwise_fp8_block_len=128
block_scaling_dim=1

# ===========================================================================
# [ADAPT] case 数据定义 —— 全部置顶，供 --list-cases / --case 引用
# ===========================================================================

_DT_NAMES = {
    torch.float32: 'fp32', torch.float16: 'fp16', torch.bfloat16: 'bf16',
    torch.int8: 'int8', torch.float8_e4m3fn: 'e4m3', torch.float8_e5m2: 'e5m2',
}

# 组名 -> 描述（dict 顺序即文档顺序；all 的展开顺序由 _ALL_GROUPS 显式固定）。
_CASE_DESCRIPTIONS = {
    'default': '基准配置（2048x2000 fp32->int8 COMPACT 双输出）',
    'dtype':   '输入/输出 dtype 矩阵 3x3（2048x2048 GEMM_READY 双输出，隔离 dtype 变量）',
    'layout':  'GEMM_READY/COMPACT x 双输出/仅rowwise x pow2 T/F（bf16->e4m3）',
    'ragged':  '非对齐 shape 矩阵（K/M 不整除分块，走非对齐慢路径）',
    'size':    'bench 主力矩阵（bf16->e4m3 GEMM_READY 双输出 + fp32->int8 COMPACT 代表点）',
    'columnwise_only': '仅 columnwise 输出（rowwise 侧传 None 的正向组合，atol=0 对拍）',
    'exc':     '异常契约组（6 条，校验入口报错行为；不计性能）',
}

_ALL_GROUPS = ['default', 'dtype', 'layout', 'ragged', 'size',
               'columnwise_only', 'exc']

# 数值组 case：dict + note 字段（--list-cases 的显示名，必填）。
# 公共约定：eps=0.0；N 为 dim-1 长度（量化 K 维）。
DEFAULT_CASES = [
    dict(M=2048, N=2000, x_dtype=torch.float32, quant_dtype=torch.int8,
         eps=0.0, pow2=True, compact=True, return_transpose=True,
         note='2048x2000 fp32->int8 COMPACT dual pow2 (基准配置)'),
]

DTYPE_SUITE = [
    dict(M=2048, N=2048, x_dtype=xd, quant_dtype=qd, eps=0.0,
         pow2=True, compact=False, return_transpose=True,
         note=f'2048x2048 {_DT_NAMES[xd]}->{_DT_NAMES[qd]} GEMM dual pow2')
    for xd in (torch.float32, torch.float16, torch.bfloat16)
    for qd in (torch.int8, torch.float8_e4m3fn, torch.float8_e5m2)
]

LAYOUT_SUITE = [
    dict(M=2048, N=2048, x_dtype=torch.bfloat16, quant_dtype=torch.float8_e4m3fn,
         eps=0.0, pow2=p2, compact=cp, return_transpose=rt,
         note=f'2048x2048 bf16->e4m3 '
              f'{"COMPACT" if cp else "GEMM"} {"dual" if rt else "rowwise-only"} pow2={p2}')
    for cp in (False, True)
    for rt in (True, False)
    for p2 in (True, False)
]

RAGGED_SUITE = [
    dict(M=m, N=k, x_dtype=torch.bfloat16, quant_dtype=torch.float8_e4m3fn,
         eps=0.0, pow2=True, compact=cp, return_transpose=True,
         note=f'M{m} K{k} {"COMPACT" if cp else "GEMM"} dual bf16->e4m3')
    for k in (2000, 2112)
    for m in (2000, 2112)
    for cp in (False, True)
]

SIZE_SUITE = (
    [dict(M=m, N=k, x_dtype=torch.bfloat16, quant_dtype=torch.float8_e4m3fn,
          eps=0.0, pow2=True, compact=False, return_transpose=True,
          note=f'M{m} K{k} bf16->e4m3 GEMM dual pow2')
     for m, k in ((2048, 2048), (4096, 4096), (4096, 5120), (4096, 7168),
                  (16384, 2048), (16384, 4096), (16384, 7168))]
    + [dict(M=2048, N=2000, x_dtype=torch.float32, quant_dtype=torch.int8,
            eps=0.0, pow2=True, compact=True, return_transpose=True,
            note='M2048 K2000 fp32->int8 COMPACT dual pow2'),
       dict(M=16384, N=7168, x_dtype=torch.float32, quant_dtype=torch.int8,
            eps=0.0, pow2=True, compact=True, return_transpose=True,
            note='M16384 K7168 fp32->int8 COMPACT dual pow2')]
)

# 仅 columnwise 输出的正向组（rowwise 侧传 None）。
COLUMNWISE_ONLY_SUITE = [
    dict(M=2048, N=2048, x_dtype=torch.bfloat16, quant_dtype=torch.float8_e4m3fn,
         eps=0.0, pow2=True, compact=False, return_transpose=True, columnwise_only=True,
         note='2048x2048 bf16->e4m3 GEMM columnwise-only（atol=0 对拍）'),
]

# 异常契约组（校验入口报错行为，不计性能）：
#   exc:1/2 block_len 非法值 -> RuntimeError 含 "block_len"
#   exc:3   仅 columnwise -> 正常执行（rowwise 输出传 None，不可解引用）
#   exc:4/5 flag 与 optional 实参不一致 -> RuntimeError
#   exc:6   non-contiguous input -> RuntimeError
_EXCEPTION_GROUP = 'exc'
_EXCEPTION_ENTRIES = [
    ('block_len', 100),
    ('block_len', 64),
    ('columnwise_only', None),
    ('flag_mismatch_rowwise', None),
    ('flag_mismatch_columnwise', None),
    ('non_contiguous', None),
]

# 期望表：kind -> (期望模式, RuntimeError 消息须含的子串)
#   'raise' = 必须 RuntimeError；'ok' = 必须正常执行
_EXC_EXPECT = {
    'block_len':                ('raise', 'block_len'),
    'columnwise_only':          ('ok', None),
    'flag_mismatch_rowwise':    ('raise', 'rowwise flag'),
    'flag_mismatch_columnwise': ('raise', 'columnwise flag'),
    'non_contiguous':           ('raise', 'contiguous'),
}


# ===========================================================================
# 对拍基石（语义不得修改）：参考量化器与形状工具
# ===========================================================================

def scale_from_amax_tensor(
    x_dtype: torch.dtype,
    amax: torch.Tensor,
    quant_dtype: torch.dtype,
    *,
    eps: float,
    pow_2_scales: bool,
) -> Tuple[torch.Tensor, torch.Tensor, torch.Tensor]:
    """Derives quantization and dequantization from amax and options.

    Reference implementation for scale calculation.

    Returns:
    - scale: quantization scales
    - scale_inv: dequantization scales
    - amax: Amax tensor with updates made for extrema values.
    """
    assert amax.dtype == torch.float, "amax must be a float tensor."
    if quant_dtype == torch.int8:
        fp8_max = torch.iinfo(quant_dtype).max
    else:
        fp8_max = torch.finfo(quant_dtype).max
    # Clamping amax to avoid division by small numbers
    amax = torch.max(amax, torch.tensor(eps))

    # Compute scale factor
    scale = torch.div(fp8_max, amax)
    # Note frexp doesn't give back inf for exponent with an inf input
    # We take care of inf before pow_2_scales
    scale = torch.where(scale == torch.inf, torch.finfo(x_dtype).max, scale)
    if pow_2_scales:
        # Calculate rounded down exponent
        _, exp = torch.frexp(scale)
        # Positive numbers are always returned as mant, exp with
        # a mantissa in [0.5, 1.0). Because a normal float has a mantissa with
        # hidden bit in [1.0, 2.0), the exponent will be off by exactly one because
        # of the shift. Subnormal and zero cases need not be considered because
        # the smallest possible result of fp8_max / amax is still normal.
        exp = exp - 1
        # No subnormals and zero.
        assert (exp > -127).all()
        unity = torch.tensor([1.0], device=exp.device)
        if IS_HIP_EXTENSION:
            host_scale = torch.ldexp(unity.cpu(), exp.cpu())
            scale = host_scale.to(exp.device)
        else:
            torch.ldexp(unity, exp, out=scale)
        # Case where amax is inf. The frexp, ldexp logic changes 0.0 scales
        # Return 0.0 for 0.0 scale for consistency with non-pow2 scale
        # calculation.
        scale = torch.where(amax == float("inf"), 0.0, scale)

    # Handle overflow cases for amax zero causing NaN
    scale = torch.where(amax == 0, 1.0, scale)

    # Compute scale_inv
    scale_inv = torch.reciprocal(scale)

    return scale, scale_inv, amax


@dataclasses.dataclass()
class QuantizeResult:
    data: torch.Tensor
    scale: torch.Tensor
    data_t: Optional[torch.Tensor]
    scale_t: Optional[torch.Tensor]


@dataclasses.dataclass()
class CuBLASScaleMunger:
    def munge_scale_shapes_for_backend(
        self,
        unmunged: QuantizeResult,
        tile_shape: Tuple[int, int],
    ) -> QuantizeResult:
        """
        cuBLAS GEMMs requires 1x128 quantized tensors to be have scales transposed
        so that for an (M, N) tensor, the scales are (RoundUpDiv(N, 128), RoundUp(M, 4))

        For 128x128 quantized tensors, the GEMM expects (M, PadToAlign(RoundUpDivide(N, 128), 4))
        format. If RoundUpDivide(N, 128) is not divisible by 4, a transformation is required
        """

        def _pad_inner_to_align(s: torch.Tensor, transpose: bool) -> torch.Tensor:
            if transpose:
                s = s.transpose(-1, -2).contiguous()
            M, K = s.shape
            if K % 4 == 0:
                return s
            k_pad = 4 - (K % 4)
            return torch.nn.functional.pad(s, (0, k_pad), mode="constant", value=0).contiguous()

        s = _pad_inner_to_align(unmunged.scale, transpose=tile_shape[0] == 1)
        if unmunged.scale_t is None:
            s_t = None
        else:
            s_t = _pad_inner_to_align(unmunged.scale_t, transpose=tile_shape[0] == 1)
        return QuantizeResult(unmunged.data, s, unmunged.data_t, s_t)

    def demunge_scale_shape_from_backend(
        cls,
        qtensor_shape: Tuple[int, int],
        scales: torch.Tensor,
        tile_shape: Tuple[int, int],
    ) -> torch.Tensor:
        """
        Inverse operation of munge_scale_shapes_for_backend
        """
        if tile_shape[0] != 1:
            # 2D block quantized tensor may need padding stripped off
            derived_scale_k_shape = math.ceil(qtensor_shape[1] / tile_shape[1])
        else:
            derived_scale_k_shape = qtensor_shape[0]
        M, K = scales.shape
        if derived_scale_k_shape != K:
            scales = scales[:, :derived_scale_k_shape].contiguous()
        if tile_shape[0] == 1:
            return scales.transpose(-1, -2).contiguous()
        else:
            return scales


@dataclasses.dataclass()
class BlockwiseQuantizerReference:
    """
    A reference QuantizeOp for subchannel/block hybrid quantization.

    Defers to ref GEMMs and quantizization formatting based on the backend.
    """

    def __init__(self) -> None:
        self.scale_munger = CuBLASScaleMunger()


    def _quantize_square_block_tiling(
        cls,
        x: torch.Tensor,
        quant_dtype: torch.dtype,
        tile_len: int,
        *,
        return_transpose: bool,
        pow_2_scales: bool,
        eps: float,
    ) -> QuantizeResult:
        M, K = x.shape

        pad_m_k = [0, 0]
        if K % tile_len != 0:
            pad_m_k[1] = tile_len - (K % tile_len)
        if M % tile_len != 0:
            pad_m_k[0] = tile_len - (M % tile_len)

        unpadded_m, unpadded_k = M, K
        if pad_m_k[0] != 0 or pad_m_k[1] != 0:
            x = torch.nn.functional.pad(
                x, (0, pad_m_k[1], 0, pad_m_k[0]), mode="constant", value=0
            ).contiguous()
            M, K = x.shape

        x_tiled = x.reshape(M // tile_len, tile_len, K // tile_len, tile_len)
        amax_grid = (
            torch.abs(x_tiled.transpose(-3, -2))
            .reshape(M // tile_len, K // tile_len, tile_len**2)
            .amax(dim=-1)
        ).float()
        if quant_dtype == torch.int8:
            dtype_max = torch.iinfo(quant_dtype).max
        else:
            dtype_max = torch.finfo(quant_dtype).max

        scale, scale_inv, _ = scale_from_amax_tensor(
            x_dtype=x.dtype,
            amax=amax_grid,
            quant_dtype=quant_dtype,
            pow_2_scales=pow_2_scales,
            eps=eps,
        )
        qx = x_tiled * scale.reshape(M // tile_len, 1, K // tile_len, 1)
        qx = torch.clamp(qx, min=-dtype_max, max=dtype_max)
        if quant_dtype == torch.int8:
            positive_mask = qx >= 0
            negative_mask = ~positive_mask
            pos_part = torch.where(positive_mask, torch.floor(qx + 0.5), 0)
            neg_part = torch.where(negative_mask, torch.ceil(qx - 0.5), 0)
            qx = pos_part + neg_part
        qx = qx.to(dtype=quant_dtype)
        qx = qx.reshape(M, K)
        if unpadded_k != K or unpadded_m != M:
            qx = qx[:unpadded_m, :unpadded_k].contiguous()
        if return_transpose:
            # Valid because of square block sizes
            qx_t = qx.transpose(-1, -2).contiguous()
            scale_inv_t = scale_inv.transpose(-1, -2).contiguous()
        else:
            qx_t = None
            scale_inv_t = None

        return QuantizeResult(data=qx, scale=scale_inv, data_t=qx_t, scale_t=scale_inv_t)


    def _quantize_vectorwise_reference(
        cls,
        x: torch.Tensor,
        quant_dtype: torch.dtype,
        tile_len: int,
        *,
        pow_2_scales: bool,
        eps: float,
    ) -> Tuple[torch.Tensor, torch.Tensor]:
        M, K = x.shape
        if quant_dtype == torch.int8:
            dtype_max = torch.iinfo(quant_dtype).max
        else:
            dtype_max = torch.finfo(quant_dtype).max
        x_tiled = x.reshape(M, K // tile_len, tile_len)
        amax_grid = torch.abs(x_tiled).amax(dim=-1).float()
        scale, scale_inv, _ = scale_from_amax_tensor(
            x_dtype=x.dtype,
            amax=amax_grid,
            quant_dtype=quant_dtype,
            pow_2_scales=pow_2_scales,
            eps=eps,
        )
        qx = x_tiled * scale.reshape(M, K // tile_len, 1)
        qx = torch.clamp(qx, min=-dtype_max, max=dtype_max)
        if quant_dtype == torch.int8:
            positive_mask = qx >= 0
            negative_mask = ~positive_mask
            pos_part = torch.where(positive_mask, torch.floor(qx + 0.5), 0)
            neg_part = torch.where(negative_mask, torch.ceil(qx - 0.5), 0)
            qx = pos_part + neg_part
        qx = qx.to(dtype=quant_dtype)
        qx = qx.reshape(M, K)
        return qx, scale_inv


    def _quantize_vector_tiling(
        cls,
        x: torch.Tensor,
        quant_dtype: torch.dtype,
        tile_len: int,
        *,
        return_transpose: bool,
        pow_2_scales: bool,
        eps: float,
    ) -> QuantizeResult:
        M, K = x.shape

        if K % tile_len == 0:
            qref_input = x
        else:
            pad_amount = tile_len - (K % tile_len)
            pad = (0, pad_amount)
            qref_input = torch.nn.functional.pad(x, pad, mode="constant", value=0)
        qout_padded, scale_inv = cls._quantize_vectorwise_reference(
            qref_input,
            quant_dtype,
            tile_len=tile_len,
            pow_2_scales=pow_2_scales,
            eps=eps,
        )
        if K % tile_len == 0:
            qout = qout_padded
        else:
            qout = qout_padded[:, :K].contiguous()

        if return_transpose:
            if M % tile_len == 0:
                qref_input = x.transpose(-1, -2).contiguous()
            else:
                amount_to_pad = tile_len - (M % tile_len)
                pad = (0, amount_to_pad)
                qref_input = torch.nn.functional.pad(
                    x.transpose(-1, -2), pad, mode="constant", value=0
                ).contiguous()
            qout_t_padded, scale_inv_t = cls._quantize_vectorwise_reference(
                qref_input,
                quant_dtype,
                tile_len=tile_len,
                pow_2_scales=pow_2_scales,
                eps=eps,
            )
            if M % tile_len == 0:
                qout_t = qout_t_padded
            else:
                qout_t = qout_t_padded[:, :M].contiguous()
        else:
            qout_t, scale_inv_t = None, None

        return QuantizeResult(data=qout, scale=scale_inv, data_t=qout_t, scale_t=scale_inv_t)

    def quantize(
        self,
        x: torch.Tensor,
        quant_dtype: torch.dtype,
        return_transpose: bool = False,
        eps: float = 0.0,
        pow_2_scales: bool = False,
        quant_tile_shape: Tuple[int, int] = (blockwise_fp8_block_len, blockwise_fp8_block_len),
        munge_scale_shapes: bool = True,
    ) -> QuantizeResult:
        # sanity checks
        assert x.dim() == 2
        assert x.dtype in (
            torch.float,
            torch.float16,
            torch.bfloat16,
            torch.float32,
        ), "Unsupported input dtype."
        assert quant_dtype in (
            torch.float8_e4m3fn,
            torch.float8_e5m2,
            torch.int8,
        ), "Unsupported quant dtype."

        assert quant_tile_shape in ((1, blockwise_fp8_block_len), (blockwise_fp8_block_len, blockwise_fp8_block_len))
        if quant_tile_shape[0] == 1:
            # Quantize row-wise
            result = self._quantize_vector_tiling(
                x,
                quant_dtype,
                tile_len=quant_tile_shape[1],
                return_transpose=return_transpose,
                pow_2_scales=pow_2_scales,
                eps=eps,
            )
            if munge_scale_shapes:
                result = self.scale_munger.munge_scale_shapes_for_backend(
                    result,
                    quant_tile_shape,
                )
            return result
        else:
            # Quantize block-wise
            result = self._quantize_square_block_tiling(
                x,
                quant_dtype,
                tile_len=quant_tile_shape[0],
                return_transpose=return_transpose,
                pow_2_scales=pow_2_scales,
                eps=eps,
            )
            if munge_scale_shapes:
                result = self.scale_munger.munge_scale_shapes_for_backend(
                    result,
                    quant_tile_shape,
                )
            return result


def initialize_for_many_scales(
    x_shape_2d: Tuple[int, int], tile_shape: Tuple[int, int], *, dtype: torch.dtype, device: str
) -> torch.Tensor:
    """
    Put separate distributions into each quantization tile
    to avoid many tiles having similar scale values and
    causing false passes.
    """
    tile_grid_shape = (
        math.ceil(x_shape_2d[0] / tile_shape[0]),
        math.ceil(x_shape_2d[1] / tile_shape[1]),
    )
    # Arbitrary size
    max_val = 8192.0
    # Make a uniform distribution of [-max_val, max_val]
    tile_extrema = torch.rand(*tile_grid_shape, dtype=dtype) * max_val * 2 - max_val
    result = torch.empty(x_shape_2d, dtype=dtype, device=device)
    tile_elements = tile_shape[0] * tile_shape[1]
    for i in range(tile_grid_shape[0]):
        for j in range(tile_grid_shape[1]):
            target = tile_extrema[i, j].item()
            step = target / (tile_elements)
            if target == 0:
                tile = torch.zeros(tile_shape, dtype=dtype, device=device)
            else:
                tile = torch.arange(0.0, target, step=step, dtype=dtype, device=device)
            tile = tile.reshape(*tile_shape)
            min_dst_vals = (i * tile_shape[0], j * tile_shape[1])
            max_dst_vals = (
                min((i + 1) * tile_shape[0], x_shape_2d[0]),
                min((j + 1) * tile_shape[1], x_shape_2d[1]),
            )
            max_src_vals = (
                max_dst_vals[0] - min_dst_vals[0],
                max_dst_vals[1] - min_dst_vals[1],
            )
            result[min_dst_vals[0] : max_dst_vals[0], min_dst_vals[1] : max_dst_vals[1]] = tile[
                : max_src_vals[0], : max_src_vals[1]
            ]
    return result


def round_up_to_nearest_multiple(value, multiple):
    """Round up `value` to the next mutiple of `multiple`"""
    if multiple == 0:
        raise ValueError("multiple cannot be zero.")
    return ((value + multiple - 1) // multiple) * multiple


def get_scale_shape(shape: Iterable[int], columnwise: bool, all_gather_usage: bool) -> Tuple[int, int]:

    M, K = 1, 1
    for i in range(len(shape) - 1):
        M *= shape[i]
    if len(shape) > 0:
        K = shape[-1]

    if columnwise:
        columnwise_compact = all_gather_usage
        outer = math.ceil(M / blockwise_fp8_block_len)
        inner = round_up_to_nearest_multiple(K, 4) if not columnwise_compact else K

        return (outer, inner)
    # rowwise
    rowwise_compact = all_gather_usage
    outer = math.ceil(K / blockwise_fp8_block_len)
    inner = round_up_to_nearest_multiple(M, 4) if not rowwise_compact else M

    return (outer, inner) if not rowwise_compact else (inner, outer)


def get_columnwise_shape(shape: Iterable[int]) -> Tuple[int, ...]:

    if len(shape) == 0:
        return tuple()

    colwise_shape = [shape[-1]]
    for i in range(len(shape) - 1):
        colwise_shape.append(shape[i])
    return tuple(colwise_shape)


# ===========================================================================
# 计时与执行（输入生成 / 内核调用 / 对拍）
# ===========================================================================

def _bench_gpu_events(fn, warmup=20, iters=200, batch=10):
    """Benchmark ``fn`` with CUDA events; returns median per-call ms.

    ``warmup`` runs are not timed (also cover first-call initialization);
    ``iters`` timed calls are grouped in ``batch`` per CUDA-event pair and the
    per-call medians are taken over ``iters // batch`` samples.
    （口径与 aiter/op_tests/test_fused_metadata.py benchmark_gpu_events 一致）
    """
    for _ in range(warmup):
        fn()
    torch.cuda.synchronize()

    start_event = torch.cuda.Event(enable_timing=True)
    end_event = torch.cuda.Event(enable_timing=True)

    times = []
    for _ in range(iters // batch):
        start_event.record()
        for _ in range(batch):
            fn()
        end_event.record()
        torch.cuda.synchronize()
        times.append(start_event.elapsed_time(end_event) / batch)

    times.sort()
    return times[len(times) // 2]


def _verify_correctness(M, N, x, quant_dtype, eps, pow2, compact, return_transpose,
                        rowwise_data, rowwise_scale_inv,
                        columnwise_data, columnwise_scale_inv):
    """正确性对拍（atol=0, rtol=0）。

    - COMPACT（all_gather_usage=True）：参考量化 munge_scale_shapes=False；
      转置输出经二次 transpose 后与 (M, N) 形状的 columnwise 缓冲比较；scale 直接比较。
    - GEMM_READY（all_gather_usage=False）：参考量化走 munge（默认 True）；
      scale 比较带 GEMM_READY padding 掩码。
    """
    tile_size = (1, blockwise_fp8_block_len)
    ref_quantizer = BlockwiseQuantizerReference()

    if rowwise_data is None:
        # columnwise-only：仅对拍 columnwise 输出（GEMM_READY 掩码逻辑同下）
        assert columnwise_data is not None and columnwise_scale_inv is not None
        qx_t = columnwise_data.view(dtype=quant_dtype)
        sx_t = columnwise_scale_inv
        qresult_ref = ref_quantizer.quantize(
            x, quant_dtype=quant_dtype, return_transpose=True, eps=eps,
            pow_2_scales=pow2, quant_tile_shape=tile_size, munge_scale_shapes=not compact)
        qx_t_ref, sx_t_ref = qresult_ref.data_t, qresult_ref.scale_t
        if not compact:
            scale_mask = torch.ones(
                (math.ceil(N / tile_size[0]), math.ceil(M / tile_size[1])),
                device=sx_t.device,)
            scale_mask = ref_quantizer.scale_munger.munge_scale_shapes_for_backend(
                QuantizeResult(qx_t, scale_mask, None, None), tile_size).scale
            sx_t = sx_t * scale_mask
        torch.testing.assert_close(qx_t.float(), qx_t_ref.float(), atol=0.0, rtol=0.0)
        torch.testing.assert_close(sx_t, sx_t_ref, atol=0.0, rtol=0.0)
        return

    assert rowwise_data is not None
    qx: torch.Tensor = rowwise_data.view(dtype=quant_dtype)
    assert rowwise_scale_inv is not None
    sx: torch.Tensor = rowwise_scale_inv
    qx_t = columnwise_data
    sx_t = columnwise_scale_inv

    qresult_ref = ref_quantizer.quantize(
        x,
        quant_dtype=quant_dtype,
        return_transpose=return_transpose,
        eps=eps,
        pow_2_scales=pow2,
        quant_tile_shape=tile_size,
        munge_scale_shapes=not compact,
    )

    qx_ref, sx_ref, qx_t_ref, sx_t_ref = (
        qresult_ref.data,
        qresult_ref.scale,
        qresult_ref.data_t,
        qresult_ref.scale_t,
    )

    if compact and return_transpose:
        # match the reference quantize transpose output with the columnwise non-transpose method
        qx_t_ref = qx_t_ref.transpose(-1, -2).contiguous()
        sx_t_ref = sx_t_ref.transpose(-1, -2).contiguous()

    # Check
    torch.testing.assert_close(qx.float(), qx_ref.float(), atol=0.0, rtol=0.0)
    if compact:
        torch.testing.assert_close(sx, sx_ref, atol=0.0, rtol=0.0)
    else:
        # GEMM_READY rowwise scale padding 掩码
        scale_mask = torch.ones(
            (math.ceil(M / tile_size[0]), math.ceil(N / tile_size[1])), device=sx.device)
        scale_mask = ref_quantizer.scale_munger.munge_scale_shapes_for_backend(
            QuantizeResult(qx, scale_mask, None, None), tile_size
        ).scale
        sx = sx * scale_mask
        torch.testing.assert_close(sx, sx_ref, atol=0.0, rtol=0.0)

    if return_transpose:
        assert qx_t is not None
        qx_t = qx_t.view(dtype=quant_dtype)
        assert qx_t_ref is not None
        assert sx_t is not None
        assert sx_t_ref is not None
        if not compact:
            # GEMM_READY 转置 scale padding 掩码
            scale_mask = torch.ones(
                (math.ceil(N / tile_size[0]), math.ceil(M / tile_size[1])),
                device=sx_t.device,)
            scale_mask = ref_quantizer.scale_munger.munge_scale_shapes_for_backend(
                QuantizeResult(qx_t, scale_mask, None, None), tile_size).scale
            sx_t = sx_t * scale_mask
        torch.testing.assert_close(qx_t.float(), qx_t_ref.float(), atol=0.0, rtol=0.0)
        torch.testing.assert_close(sx_t, sx_t_ref, atol=0.0, rtol=0.0)
    else:
        # should be None
        assert qx_t is None and qx_t_ref is None
        assert sx_t is None and sx_t_ref is None


def _run_one(kw, bench_only, warmup, iters):
    """执行一个数值 case：正确性对拍（bench_only 时跳过）+ 基准计时。

    正确性经公开 API aiter.blockwise_scaled_cast_transpose（@compile_ops 桩）；
    计时直调 module_blockwise_scaling pybind 绑定（绕过 compile_ops wrapper）。
    kernel 调用参数序（13 参）：
    (x, output, scale_inv, output_t, scale_inv_t, block_len, block_scaling_dim,
     rowwise, columnwise, epsilon, pow2_scale, all_gather_usage, out_dtype)。

    返回 (ok, t_ref_ms, t_impl_ms)；RuntimeError（内核缺陷，ragged 组预期失败源
    之一）按 FAIL 记录不中断全量运行，该 case 跳过计时。
    """
    M, N = kw['M'], kw['N']
    x_dtype, quant_dtype = kw['x_dtype'], kw['quant_dtype']
    eps, pow2 = kw['eps'], kw['pow2']
    compact, return_transpose = kw['compact'], kw['return_transpose']

    tile_size = (1, blockwise_fp8_block_len)
    ref_quantizer = BlockwiseQuantizerReference()
    device = "cuda"
    seed = 0
    torch.manual_seed(seed)
    torch.cuda.manual_seed(seed)

    # Input（逐 tile 独立分布，覆盖不同 scale 组合）
    x = initialize_for_many_scales((M, N), tile_size, dtype=x_dtype, device=device)

    # caller-alloc 输出缓冲（按 compact/return_transpose 参数化分配；
    # columnwise_only 组合 rowwise 侧传 None）
    if kw.get('columnwise_only', False):
        rowwise_data = rowwise_scale_inv = None
        columnwise_data = torch.empty(get_columnwise_shape((M, N)), dtype=torch.uint8, device=device)
        columnwise_scale_inv = torch.empty(
            get_scale_shape((M, N), columnwise=True, all_gather_usage=compact),
            dtype=torch.float32, device=device)
    else:
        rowwise_data = torch.empty((M, N), dtype=torch.uint8, device=device)
        if compact:
            scale_inv_shape = get_scale_shape((M, N), columnwise=False, all_gather_usage=True)
            rowwise_scale_inv = torch.empty(scale_inv_shape, dtype=torch.float32, device=device)
            if return_transpose:
                columnwise_data = torch.empty((M, N), dtype=torch.uint8, device=device)
                columnwise_scale_shape = get_scale_shape((M, N), columnwise=True, all_gather_usage=True)
                columnwise_scale_inv = torch.empty(columnwise_scale_shape, dtype=torch.float32, device=device)
            else:
                columnwise_data, columnwise_scale_inv = None, None
        else:
            scale_inv_shape = get_scale_shape((M, N), columnwise=False, all_gather_usage=False)
            rowwise_scale_inv = torch.empty(scale_inv_shape, dtype=torch.float32, device=device)
            if return_transpose:
                columnwise_data = torch.empty(get_columnwise_shape((M, N)), dtype=torch.uint8, device=device)
                columnwise_scale_shape = get_scale_shape((M, N), columnwise=True, all_gather_usage=False)
                columnwise_scale_inv = torch.empty(columnwise_scale_shape, dtype=torch.float32, device=device)
            else:
                columnwise_data, columnwise_scale_inv = None, None

    # ---- 正确性（bench_only 跳过）：公开 API + 对拍 ----
    ok, timed_ok = True, True
    if not bench_only:
        try:
            aiter.blockwise_scaled_cast_transpose(
                x, rowwise_data, rowwise_scale_inv, columnwise_data, columnwise_scale_inv,
                blockwise_fp8_block_len, block_scaling_dim,
                not kw.get('columnwise_only', False), return_transpose,
                eps, pow2, compact, quant_dtype)
            _verify_correctness(M, N, x, quant_dtype, eps, pow2, compact, return_transpose,
                                rowwise_data, rowwise_scale_inv,
                                columnwise_data, columnwise_scale_inv)
        except AssertionError:
            ok = False
        except RuntimeError as e:
            # v1 内核缺陷（如 ragged 组预期失败）：按 FAIL 记录，不中断全量运行
            ok, timed_ok = False, False
            print(f"  [case {kw['note']}] kernel RuntimeError: {e}")

    # ---- 基准计时：直调 pybind 绑定 ----
    t_ref = t_impl = None
    if timed_ok:
        op_fn = _get_aiter_fn()

        def _impl_call():
            op_fn(x, rowwise_data, rowwise_scale_inv, columnwise_data, columnwise_scale_inv,
                  blockwise_fp8_block_len, block_scaling_dim,
                  not kw.get('columnwise_only', False), return_transpose,
                  eps, pow2, compact, quant_dtype)

        def _ref_call():
            ref_quantizer.quantize(
                x, quant_dtype=quant_dtype, return_transpose=return_transpose,
                eps=eps, pow_2_scales=pow2, quant_tile_shape=tile_size,
                munge_scale_shapes=not compact)

        t_impl = _bench_gpu_events(_impl_call, warmup, iters)
        t_ref = _bench_gpu_events(_ref_call, warmup, iters)
    return ok, t_ref, t_impl


def _build_case_kw(case):
    """case -> 测试输入 dict（case 字段即运行参数，见文件头字段约定）。"""
    return dict(case)


# ===========================================================================
# 异常契约组执行 —— 真实调用内核并按 _EXC_EXPECT 校验行为
# ===========================================================================

_EXC_SHAPE = (256, 256)  # 256 % 128 == 0，full_tile 路径；尺寸取小以加速异常轮


def _run_exc_case(kind, val):
    """异常组单条目执行：构造输入 → 调用算子 → 按期望表校验。

    返回 (ok, detail)；ok=True 表示行为符合契约。
    注意：须在 AITER_REBUILD=1 重编后运行（旧 v1 .so 的 14 参签名与新桩不匹配）。
    """
    mode, substr = _EXC_EXPECT[kind]
    M, N = _EXC_SHAPE
    dev = "cuda"
    x = torch.randn((M, N), dtype=torch.bfloat16, device=dev)
    out = torch.empty((M, N), dtype=torch.uint8, device=dev)
    s = torch.empty(get_scale_shape((M, N), columnwise=False, all_gather_usage=False),
                    dtype=torch.float32, device=dev)
    ot = torch.empty(get_columnwise_shape((M, N)), dtype=torch.uint8, device=dev)
    st = torch.empty(get_scale_shape((M, N), columnwise=True, all_gather_usage=False),
                     dtype=torch.float32, device=dev)
    e4m3 = torch.float8_e4m3fn
    bl = val if kind == 'block_len' else blockwise_fp8_block_len

    if kind == 'block_len':
        # block_len ∉ {128} → 入口 TORCH_CHECK（消息含 block_len）
        args = (x, out, s, ot, st, bl, block_scaling_dim, True, True, 0.0, True, False, e4m3)
    elif kind == 'columnwise_only':
        # 仅 columnwise（output/scale_inv=None）→ 正常执行
        args = (x, None, None, ot, st, bl, block_scaling_dim, False, True, 0.0, True, False, e4m3)
    elif kind == 'flag_mismatch_rowwise':
        # rowwise=True 但 output=None
        args = (x, None, s, None, None, bl, block_scaling_dim, True, False, 0.0, True, False, e4m3)
    elif kind == 'flag_mismatch_columnwise':
        # columnwise=True 但 output_transpose=None
        args = (x, out, s, None, None, bl, block_scaling_dim, True, True, 0.0, True, False, e4m3)
    elif kind == 'non_contiguous':
        # non-contiguous input（转置别名）
        args = (x.t(), out, s, ot, st, bl, block_scaling_dim, True, True, 0.0, True, False, e4m3)
    else:
        raise SystemExit(f"error: unknown exception kind {kind!r}")

    try:
        aiter.blockwise_scaled_cast_transpose(*args)
        torch.cuda.synchronize()
        raised, msg = False, ''
    except RuntimeError as e:
        raised, msg = True, str(e)

    if mode == 'raise':
        ok = raised and (substr is None or substr in msg)
        if ok:
            detail = 'PASS: raised RuntimeError' + (f' containing {substr!r}' if substr else '')
        else:
            detail = ('FAIL: expected RuntimeError'
                      + (f' containing {substr!r}' if substr else '')
                      + ', got ' + ('no raise' if not raised else msg.splitlines()[0]))
    else:  # 'ok'
        ok = not raised
        detail = ('PASS: executed without error' if ok
                  else f'FAIL: unexpected RuntimeError: {msg.splitlines()[0]}')
    return ok, detail


# 数值组 dispatch 表：case_id -> (case 列表, 构造函数)。
_NUMERIC_CASES = {
    'default': (DEFAULT_CASES, _build_case_kw),
    'dtype':   (DTYPE_SUITE,   _build_case_kw),
    'layout':  (LAYOUT_SUITE,  _build_case_kw),
    'ragged':  (RAGGED_SUITE,  _build_case_kw),
    'size':    (SIZE_SUITE,    _build_case_kw),
    'columnwise_only': (COLUMNWISE_ONLY_SUITE, _build_case_kw),
}


# ===========================================================================
# --case token 解析 / 越界校验 / --list-cases
# ===========================================================================

def _parse_case_token(token):
    """'v2' -> ('v2', None)；'v2:3' -> ('v2', 3)。"""
    group, sep, idx_str = token.partition(':')
    if not sep:
        return group, None
    try:
        index = int(idx_str)
    except ValueError:
        raise SystemExit(f"error: invalid case index in --case {token!r}")
    if index <= 0:
        raise SystemExit(f"error: case index must be 1-based in --case {token!r}")
    return group, index


def _check_case_index(case_id, index, count):
    """校验 --case 组名:N 的 1-based 序号，越界时报错并退出。"""
    if not 1 <= index <= count:
        raise SystemExit(
            f"error: --case {case_id}:{index} out of range (1..{count}); "
            f"use --list-cases to enumerate cases")


def _list_cases():
    """打印全部 case 组及其 1-based case 序号（供 --case 组名:N 引用）。"""
    for case_id, desc in _CASE_DESCRIPTIONS.items():
        print(f"[{case_id}] {desc}")
        if case_id == _EXCEPTION_GROUP:
            for i, (kind, val) in enumerate(_EXCEPTION_ENTRIES, 1):
                print(f"  {i:3d}. {kind}={val}")
        else:
            cases, _ = _NUMERIC_CASES[case_id]
            for i, case in enumerate(cases, 1):
                print(f"  {i:3d}. {case['note']}")


# ===========================================================================
# [FIXED 骨架] run_case —— 序号切片语义固定；case 执行内部为 [ADAPT]
# ===========================================================================

def run_case(case_id, bench_only=False, warmup=20, iters=200, case_index=None):
    """运行一个测试 case 组（case_index 非空时只跑组内第 case_index 个），
    返回 (passed, failed, avg_speedup)。

    数值组每例打印明细行并记录 speedup；异常组不计性能（avg 返回 None）。
    """
    passed = failed = 0
    speedups = []

    if case_id == _EXCEPTION_GROUP:
        entries = _EXCEPTION_ENTRIES
        if case_index is not None:
            _check_case_index(case_id, case_index, len(entries))
            entries = [entries[case_index - 1]]
        for kind, val in entries:
            # 真实调用算子并按 _EXC_EXPECT 校验（模板的
            # _expects_runtime_error toy 判定替换为真实执行体 _run_exc_case）
            ok, detail = _run_exc_case(kind, val)
            passed, failed = passed + ok, failed + (not ok)
            print(f"  [{kind}={val}] {detail}")
        return passed, failed, None

    cases, build = _NUMERIC_CASES[case_id]
    if case_index is not None:
        _check_case_index(case_id, case_index, len(cases))
        cases = [cases[case_index - 1]]
    for case in cases:
        ok, t_ref, t_impl = _run_one(build(case), bench_only, warmup, iters)
        if ok:
            passed += 1
            speedup = t_ref / t_impl if t_impl > 0 else float('inf')
            speedups.append(speedup)
            bench = (f" | ref {t_ref:.3f} ms | impl {t_impl:.3f} ms | "
                     f"Speedup {speedup:.2f}x") if t_impl > 0 else ""
            print(f"  [case {case['note']}] PASS{bench}")
        else:
            failed += 1
            print(f"  [case {case['note']}] FAIL (correctness mismatch)")

    avg = (sum(speedups) / len(speedups)) if speedups else None
    return passed, failed, avg


# ===========================================================================
# [FIXED] CLI 入口 —— 选择循环勿改语义；组名/帮助文案按实际调整
# ===========================================================================

def main():
    parser = argparse.ArgumentParser(
        description='Correctness & benchmark tests for aiter '
                    'blockwise_scaled_cast_transpose (1x128 row-block quant + cast + transpose)')
    parser.add_argument('--bench-only', action='store_true',
                        help='skip correctness asserts, run benchmarks only')
    parser.add_argument('--warmup', type=int, default=20,
                        help='un-timed warmup calls per benchmark (default: 20)')
    parser.add_argument('--iters', type=int, default=200,
                        help='total timed iterations per benchmark (default: 200)')
    parser.add_argument('--list-cases', action='store_true',
                        help='print all case groups with 1-based case indices, then exit')
    parser.add_argument('--case', nargs='+', default=['default'], metavar='GROUP[:N]',
                        help='default: 默认用例组；dtype/layout/ragged/size: '
                             '按测试方向分组的测试集（见 --list-cases）；all = 全部组；'
                             'GROUP:N 只运行该组第 N 个 case（1-based，见 --list-cases）')
    # 无 CLI 旧入口需保留。
    args = parser.parse_args()

    if args.list_cases:
        _list_cases()
        return

    torch.cuda.set_device(0)
    total_failed = 0

    case_ids = []
    case_indices = {}
    for token in args.case:
        group, index = _parse_case_token(token)
        if group == 'all':
            if index is not None:
                raise SystemExit(
                    "error: --case all:N is ambiguous; select a single group")
            groups = _ALL_GROUPS
        else:
            if group not in _CASE_DESCRIPTIONS:
                raise SystemExit(
                    f"error: unknown case group {group!r} "
                    f"(valid: {', '.join(_ALL_GROUPS + ['all'])})")
            groups = [group]
        for g in groups:
            case_ids.append(g)
            if index is not None:
                case_indices[g] = index

    for case_id in case_ids:
        sel = case_indices.get(case_id)
        header = f'{case_id}:{sel}' if sel is not None else case_id
        print('=' * 72)
        print(f'[CASE {header}] {_CASE_DESCRIPTIONS[case_id]}')
        print('=' * 72)
        if args.bench_only and case_id == _EXCEPTION_GROUP:
            # 异常断言组在 --bench-only 下无正确性可跳。
            print('  skipped under --bench-only (exception case)')
            continue
        passed, failed, avg = run_case(case_id, bench_only=args.bench_only,
                                       warmup=args.warmup, iters=args.iters,
                                       case_index=sel)
        if avg is not None:
            print(f"\n[CASE {case_id}] average speedup: {avg:.2f}x   "
                  f"correctness: {passed} passed, {failed} failed")
        else:
            label = 'exceptions' if case_id == _EXCEPTION_GROUP else 'correctness'
            print(f"\n[CASE {case_id}] {label}: "
                  f"{passed}/{passed + failed} passed")
        total_failed += failed

    if total_failed > 0:
        print(f"\nFAILED: {total_failed} case(s) failed overall")
        sys.exit(1)
    print("\nAll checks passed.")


if __name__ == '__main__':
    main()
