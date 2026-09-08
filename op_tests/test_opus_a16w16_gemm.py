# SPDX-License-Identifier: MIT
# Copyright (C) 2026, Hygon Info Technologies Ltd. All rights reserved.

"""BF16 Opus GEMM 测试。

请在 aiter 仓库根目录、对应 GPU 容器内执行以下命令。

kernelId 简表：

- ``None``：自动选择，普通用户推荐不传 ``kernelId``。
- ``0``：direct global-memory baseline。
- ``1``：16x16 同步 LDS baseline。
- ``2``：32x32、4-wave LDS kernel；gfx938 长 K 低并行场景可配合 split-K。
- ``3``：64x64x32 Opus layout/tiled-MMA 双缓冲 pipeline；要求 M/N 可被 64
  整除、K 可被 32 整除。

正确性测试（gfx938）：
``GPU_ARCHS=gfx938 AITER_REBUILD=1 python -m pytest -q op_tests/test_opus_a16w16_gemm.py -s``

正确性测试（gfx936）：
``GPU_ARCHS=gfx936 AITER_REBUILD=1 python -m pytest -q op_tests/test_opus_a16w16_gemm.py -s``

正确性测试（少伯 perf-model/gfx946）：
``GPU_CHIP=sb AITER_REBUILD=1 python -m pytest -q op_tests/test_opus_a16w16_gemm.py -s``

测试输入与参考 GEMM 均在 CPU 生成/计算，GPU 侧只执行待测 Opus kernel 和数据拷贝，
避免 perf-model 无法执行的 PyTorch/Triton GPU 参考 kernel。

性能测试（示例为 gfx938、M=N=K=1024；先运行正确性命令完成 JIT 编译）：
``GPU_ARCHS=gfx938 AITER_REBUILD=0 python -c 'import torch; from aiter.ops.opus import gemm_a16w16_opus as gemm; from aiter.test_common import run_perftest; M=N=K=1024; a=torch.randn((M,K),device="cuda",dtype=torch.bfloat16); b=torch.randn((N,K),device="cuda",dtype=torch.bfloat16); out=torch.empty((M,N),device="cuda",dtype=torch.float32); [(lambda us,k: print(f"kernelId={k}: {us:.3f} us, {2*M*N*K/us/1e6:.3f} TFLOP/s"))(run_perftest(gemm,a,b,out=out,dtype=torch.float32,kernelId=k,splitK=1,num_warmup=10,num_iters=100)[1],k) for k in (0,1,2,3)]'``

gfx936 性能测试只需把上述命令中的 ``GPU_ARCHS=gfx938`` 改为
``GPU_ARCHS=gfx936``。该命令仅使用 PyTorch 和 AITER 自带的
``aiter.test_common.run_perftest``，不依赖仓库外测试脚本。
"""

import pytest
import torch

from aiter.ops.opus import gemm_a16w16_opus
from aiter.jit.utils.chip_info import get_gfx


def _normalized_gfx() -> str:
    return str(get_gfx()).strip().lower().split(":", 1)[0]


pytestmark = pytest.mark.skipif(
    _normalized_gfx() not in {"gfx936", "gfx938", "gfx946"},
    reason="Opus GEMM supports gfx936, gfx938 and gfx946",
)


def _randn_cuda(shape, dtype):
    return torch.randn(shape, dtype=torch.float32).to(dtype).to("cuda")


def _reference_matmul(a, b):
    return torch.matmul(a.cpu().float(), b.cpu().float().transpose(-1, -2))


def _assert_close(actual, expected):
    torch.testing.assert_close(actual.cpu(), expected, rtol=2e-2, atol=8e-2)


@pytest.mark.parametrize("shape", [(1, 16, 16, 16), (1, 17, 19, 31), (2, 23, 29, 37)])
@pytest.mark.parametrize("out_dtype", [torch.bfloat16, torch.float32])
@pytest.mark.parametrize("kernel_id", [0, 1, 2])
def test_opus_a16w16_hcu(shape, out_dtype, kernel_id):
    batch, m, n, k = shape
    a = _randn_cuda((batch, m, k), torch.bfloat16)
    b = _randn_cuda((batch, n, k), torch.bfloat16)
    actual = gemm_a16w16_opus(a, b, dtype=out_dtype, kernelId=kernel_id)
    expected = _reference_matmul(a, b)
    if out_dtype == torch.bfloat16:
        expected = expected.bfloat16()
    _assert_close(actual, expected)


def test_opus_a16w16_hcu_2d_broadcast_b():
    a = _randn_cuda((2, 17, 31), torch.bfloat16)
    b = _randn_cuda((19, 31), torch.bfloat16)
    actual = gemm_a16w16_opus(a, b, dtype=torch.float32)
    expected = _reference_matmul(a, b)
    _assert_close(actual, expected)


def test_opus_a16w16_hcu_2d_a_and_out():
    a = _randn_cuda((17, 31), torch.bfloat16)
    b = _randn_cuda((19, 31), torch.bfloat16)
    out = torch.empty((17, 19), device="cuda", dtype=torch.bfloat16)
    actual = gemm_a16w16_opus(a, b, out=out)
    expected = _reference_matmul(a, b).bfloat16()
    assert actual.data_ptr() == out.data_ptr()
    _assert_close(actual, expected)


@pytest.mark.parametrize("out_dtype", [torch.bfloat16, torch.float32])
@pytest.mark.parametrize("bias_dtype", [torch.bfloat16, torch.float32])
@pytest.mark.parametrize("kernel_id", [0, 1, 2])
def test_opus_a16w16_hcu_bias(out_dtype, bias_dtype, kernel_id):
    a = _randn_cuda((2, 17, 31), torch.bfloat16)
    b = _randn_cuda((2, 19, 31), torch.bfloat16)
    bias = _randn_cuda((2, 19), bias_dtype)
    actual = gemm_a16w16_opus(a, b, bias=bias, dtype=out_dtype, kernelId=kernel_id)
    expected = _reference_matmul(a, b) + bias.cpu().float().unsqueeze(1)
    if out_dtype == torch.bfloat16:
        expected = expected.bfloat16()
    _assert_close(actual, expected)


@pytest.mark.parametrize("split_k", [2, 3, 4])
@pytest.mark.parametrize("out_dtype", [torch.bfloat16, torch.float32])
@pytest.mark.parametrize("kernel_id", [0, 1, 2])
def test_opus_a16w16_hcu_splitk_bias(split_k, out_dtype, kernel_id):
    a = _randn_cuda((2, 23, 79), torch.bfloat16)
    b = _randn_cuda((29, 79), torch.bfloat16)
    bias = _randn_cuda((29,), torch.float32)
    actual = gemm_a16w16_opus(
        a, b, bias=bias, dtype=out_dtype, splitK=split_k, kernelId=kernel_id
    )
    expected = _reference_matmul(a, b) + bias.cpu().float()
    if out_dtype == torch.bfloat16:
        expected = expected.bfloat16()
    _assert_close(actual, expected)


@pytest.mark.parametrize("out_dtype", [torch.bfloat16, torch.float32])
@pytest.mark.parametrize("bias_dtype", [torch.bfloat16, torch.float32])
@pytest.mark.parametrize("split_k", [1, 3])
def test_opus_a16w16_hcu_opus_pipeline(out_dtype, bias_dtype, split_k):
    """kernelId=3 的 64x64x32 Opus layout/LDS 双缓冲路径。"""
    a = _randn_cuda((2, 64, 96), torch.bfloat16)
    b = _randn_cuda((64, 96), torch.bfloat16)
    bias = _randn_cuda((64,), bias_dtype)
    actual = gemm_a16w16_opus(
        a, b, bias=bias, dtype=out_dtype, splitK=split_k, kernelId=3
    )
    expected = _reference_matmul(a, b) + bias.cpu().float()
    if out_dtype == torch.bfloat16:
        expected = expected.bfloat16()
    _assert_close(actual, expected)


def test_opus_a16w16_hcu_auto_opus_pipeline_aligned():
    a = _randn_cuda((256, 256), torch.bfloat16)
    b = _randn_cuda((256, 256), torch.bfloat16)
    actual = gemm_a16w16_opus(a, b, dtype=torch.float32)
    expected = _reference_matmul(a, b)
    _assert_close(actual, expected)


def test_opus_a16w16_hcu_rejects_excess_splitk():
    a = _randn_cuda((17, 31), torch.bfloat16)
    b = _randn_cuda((19, 31), torch.bfloat16)
    with pytest.raises(ValueError, match="cannot exceed"):
        gemm_a16w16_opus(a, b, splitK=3)


def test_opus_a16w16_gfx938_auto_lds_splitk():
    if _normalized_gfx() != "gfx938":
        pytest.skip("automatic LDS/split-K tuning is gfx938-only")
    a = _randn_cuda((32, 2048), torch.bfloat16)
    b = _randn_cuda((32, 2048), torch.bfloat16)
    actual = gemm_a16w16_opus(a, b, dtype=torch.float32)
    expected = _reference_matmul(a, b)
    _assert_close(actual, expected)


def test_opus_a16w16_gfx946_identity_layout():
    if _normalized_gfx() != "gfx946":
        pytest.skip("gfx946 MMAC fragment-layout probe")
    a = torch.eye(64, dtype=torch.bfloat16).to("cuda")
    b = torch.eye(64, dtype=torch.bfloat16).to("cuda")
    actual = gemm_a16w16_opus(a, b, dtype=torch.float32, kernelId=3)
    _assert_close(actual, torch.eye(64, dtype=torch.float32))
