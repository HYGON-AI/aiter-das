# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.

"""gfx938/gfx946 FP8 E4M3 Opus GEMM 测试。

请在 aiter 仓库根目录、gfx938 GPU 容器内执行以下命令。

kernelId 简表：

- ``None``：自动选择，普通用户推荐不传 ``kernelId``。
- ``0``：direct global-memory baseline。
- ``1``：32x32、4-wave 同步 LDS kernel。
- ``2``：64x64x64 Opus layout/tiled-MMA 双缓冲 pipeline；要求 M/N/K 均可被
  64 整除。

正确性测试：
``GPU_ARCHS=gfx938 AITER_REBUILD=1 python -m pytest -q op_tests/test_opus_a8w8_gemm.py -s``

少伯 perf-model/gfx946：
``GPU_CHIP=sb AITER_REBUILD=1 python -m pytest -q op_tests/test_opus_a8w8_gemm.py -s``

测试输入与参考 GEMM 均在 CPU 生成/计算，GPU 侧只执行待测 Opus kernel 和数据拷贝，
避免 perf-model 无法执行的 PyTorch/Triton GPU 参考 kernel。

性能测试（示例为 M=N=K=1024；先运行正确性命令完成 JIT 编译）：
``GPU_ARCHS=gfx938 AITER_REBUILD=0 python -c 'import torch; from aiter.ops.opus import gemm_a8w8_opus as gemm; from aiter.test_common import run_perftest; M=N=K=1024; a=torch.randn((M,K),device="cuda",dtype=torch.float32).to(torch.float8_e4m3fn); b=torch.randn((N,K),device="cuda",dtype=torch.float32).to(torch.float8_e4m3fn); out=torch.empty((M,N),device="cuda",dtype=torch.float32); [(lambda us,k: print(f"kernelId={k}: {us:.3f} us, {2*M*N*K/us/1e6:.3f} TFLOP/s"))(run_perftest(gemm,a,b,out=out,dtype=torch.float32,kernelId=k,num_warmup=10,num_iters=100)[1],k) for k in (0,1,2)]'``

该性能命令仅使用 PyTorch 和 AITER 自带的
``aiter.test_common.run_perftest``，不依赖仓库外测试脚本；FP8 测试支持
gfx938/gfx946，不要在 gfx936 上执行。perf-model 不用于性能测试。
"""

import pytest
import torch

from aiter.jit.utils.chip_info import get_gfx
from aiter.ops.opus import gemm_a8w8_opus


def _normalized_gfx() -> str:
    return str(get_gfx()).strip().lower().split(":", 1)[0]


pytestmark = pytest.mark.skipif(
    _normalized_gfx() not in {"gfx938", "gfx946"},
    reason="FP8 Opus GEMM supports gfx938 and gfx946",
)


def _fp8_randn(shape):
    return torch.randn(shape, dtype=torch.float32).to(torch.float8_e4m3fn).to("cuda")


def _randn_cuda(shape, dtype):
    return torch.randn(shape, dtype=torch.float32).to(dtype).to("cuda")


def _reference_matmul(a, b):
    return torch.matmul(a.cpu().float(), b.cpu().float().transpose(-1, -2))


def _assert_close(actual, expected):
    torch.testing.assert_close(actual.cpu(), expected, rtol=3e-2, atol=2e-1)


@pytest.mark.parametrize("shape", [(1, 16, 16, 32), (1, 17, 19, 37), (2, 23, 29, 79)])
@pytest.mark.parametrize("out_dtype", [torch.bfloat16, torch.float32])
@pytest.mark.parametrize("kernel_id", [0, 1])
def test_opus_a8w8_gfx938(shape, out_dtype, kernel_id):
    batch, m, n, k = shape
    a = _fp8_randn((batch, m, k))
    b = _fp8_randn((batch, n, k))
    actual = gemm_a8w8_opus(a, b, dtype=out_dtype, kernelId=kernel_id)
    expected = _reference_matmul(a, b)
    if out_dtype == torch.bfloat16:
        expected = expected.bfloat16()
    _assert_close(actual, expected)


def test_opus_a8w8_gfx938_2d_broadcast_and_out():
    a = _fp8_randn((2, 17, 37))
    b = _fp8_randn((19, 37))
    out = torch.empty((2, 17, 19), device="cuda", dtype=torch.float32)
    actual = gemm_a8w8_opus(a, b, dtype=torch.float32, out=out)
    expected = _reference_matmul(a, b)
    assert actual.data_ptr() == out.data_ptr()
    _assert_close(actual, expected)


@pytest.mark.parametrize("out_dtype", [torch.bfloat16, torch.float32])
@pytest.mark.parametrize("bias_dtype", [torch.bfloat16, torch.float32])
@pytest.mark.parametrize("kernel_id", [0, 1])
def test_opus_a8w8_gfx938_scale_bias(out_dtype, bias_dtype, kernel_id):
    a = _fp8_randn((2, 17, 69))
    b = _fp8_randn((2, 19, 69))
    bias = _randn_cuda((2, 19), bias_dtype)
    actual = gemm_a8w8_opus(
        a, b, x_scale=0.5, w_scale=0.25, bias=bias, dtype=out_dtype,
        kernelId=kernel_id,
    )
    expected = _reference_matmul(a, b) * 0.125
    expected = expected + bias.cpu().float().unsqueeze(1)
    if out_dtype == torch.bfloat16:
        expected = expected.bfloat16()
    _assert_close(actual, expected)


def test_opus_a8w8_gfx938_rejects_non_fp8():
    a = _randn_cuda((17, 32), torch.float16)
    b = _fp8_randn((19, 32))
    with pytest.raises(NotImplementedError, match="float8_e4m3fn"):
        gemm_a8w8_opus(a, b)


def test_opus_a8w8_gfx938_auto_lds():
    a = _fp8_randn((32, 2048))
    b = _fp8_randn((32, 2048))
    actual = gemm_a8w8_opus(a, b, dtype=torch.float32)
    expected = _reference_matmul(a, b)
    _assert_close(actual, expected)


@pytest.mark.parametrize("out_dtype", [torch.bfloat16, torch.float32])
@pytest.mark.parametrize("bias_dtype", [torch.bfloat16, torch.float32])
def test_opus_a8w8_gfx938_opus_pipeline(out_dtype, bias_dtype):
    """kernelId=2 的 gfx938/gfx946 64x64x64 Opus layout/LDS 双缓冲路径。"""
    a = _fp8_randn((2, 64, 128))
    b = _fp8_randn((64, 128))
    bias = _randn_cuda((64,), bias_dtype)
    actual = gemm_a8w8_opus(
        a,
        b,
        x_scale=0.5,
        w_scale=0.25,
        bias=bias,
        dtype=out_dtype,
        kernelId=2,
    )
    expected = _reference_matmul(a, b) * 0.125 + bias.cpu().float()
    if out_dtype == torch.bfloat16:
        expected = expected.bfloat16()
    _assert_close(actual, expected)


def test_opus_a8w8_gfx938_auto_opus_pipeline_aligned():
    a = _fp8_randn((256, 256))
    b = _fp8_randn((256, 256))
    actual = gemm_a8w8_opus(a, b, dtype=torch.float32)
    expected = _reference_matmul(a, b)
    _assert_close(actual, expected)


def test_opus_a8w8_gfx946_identity_layout():
    if _normalized_gfx() != "gfx946":
        pytest.skip("gfx946 FP8 MMAC fragment-layout probe")
    a = torch.eye(64, dtype=torch.float32).to(torch.float8_e4m3fn).to("cuda")
    b = torch.eye(64, dtype=torch.float32).to(torch.float8_e4m3fn).to("cuda")
    actual = gemm_a8w8_opus(a, b, dtype=torch.float32, kernelId=2)
    _assert_close(actual, torch.eye(64, dtype=torch.float32))
