# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Bitwise regression tests for the opt-in eager GELU-and-multiply API."""

import pytest
import torch
import torch.nn.functional as F

import aiter


def reference(inp):
    x, gate = inp.chunk(2, dim=-1)
    return F.gelu(x, approximate="none") * gate


def assert_eager_equal(actual, expected):
    # NaN payload/sign propagation is not an API guarantee. All non-NaN
    # values are compared as raw bits, including infinities and signed zero.
    nan_mismatch = torch.isnan(actual) != torch.isnan(expected)
    assert not nan_mismatch.any(), f"{int(nan_mismatch.sum())} NaN classifications differ"
    valid = ~torch.isnan(expected)
    mismatch = valid & (actual.view(torch.int16) != expected.view(torch.int16))
    count = int(mismatch.sum().item())
    if count:
        idx = mismatch.flatten().nonzero()[:8, 0]
        raise AssertionError(
            f"{count}/{actual.numel()} non-NaN values differ in bits; "
            f"actual={actual.flatten()[idx].tolist()}, "
            f"expected={expected.flatten()[idx].tolist()}"
        )


@pytest.mark.parametrize("dtype", [torch.bfloat16, torch.float16])
@pytest.mark.parametrize(
    "shape",
    [(2,), (7, 6), (4, 126), (3, 130), (2, 3, 514), (31, 5248), (0, 16), (2, 0)],
)
def test_shapes(dtype, shape):
    torch.manual_seed(314159)
    inp = torch.randn(shape, dtype=dtype, device="cuda")
    expected = reference(inp)
    out = torch.empty_like(expected)
    aiter.gelu_and_mul_eager(out, inp)
    assert_eager_equal(out, expected)


@pytest.mark.parametrize("dtype", [torch.bfloat16, torch.float16])
@pytest.mark.parametrize("rows", [1, 2, 4, 8, 16, 32, 64, 65, 128])
@pytest.mark.parametrize("d", [63, 65, 257, 2624, 4096, 8192])
def test_small_rows(dtype, rows, d):
    torch.manual_seed(20261016)
    inp = torch.randn((rows, 2 * d), dtype=dtype, device="cuda")
    out = torch.empty((rows, d), dtype=dtype, device="cuda")
    aiter.gelu_and_mul_eager(out, inp)
    assert_eager_equal(out, reference(inp))


@pytest.mark.parametrize("dtype", [torch.bfloat16, torch.float16])
@pytest.mark.parametrize("offset", [0, 1, 2, 4, 8])
def test_single_row_encodings_and_alignment(dtype, offset):
    # A single row takes PyTorch's contiguous/vectorized GELU path, unlike
    # the multi-row encoding test. Include a partial vectorized block too.
    values = torch.arange(65536, dtype=torch.int32).to(torch.int16).view(dtype)
    tail = torch.tensor([-0.0, -1.4853515625, 0.001338958740234375,
                         -0.001338958740234375, -6.0], dtype=dtype)
    values = torch.cat((values, tail)).cuda()
    d = values.numel()
    storage = torch.empty(2 * d + offset, dtype=dtype, device="cuda")
    inp = storage[offset:].view(1, 2 * d)
    inp[0, :d].copy_(values)
    out_storage = torch.empty(d + 3, dtype=dtype, device="cuda")
    out_storage.fill_(17)
    out = out_storage[1:1 + d].view(1, d)
    info = torch.finfo(dtype)
    for gate in [1.0, -1.0, 0.0, -0.0, 0.1, -0.1, 0.220703125, 2.0,
                 info.tiny, info.tiny * info.eps, info.max,
                 float("inf"), -float("inf"), float("nan")]:
        inp[0, d:].fill_(gate)
        aiter.gelu_and_mul_eager(out, inp)
        assert_eager_equal(out, reference(inp))
        assert out_storage[0] == 17 and (out_storage[-2:] == 17).all()


@pytest.mark.parametrize("d", [2047, 2048, 2049, 2624, 4096])
def test_fp16_vectorized_rounding_boundary(d):
    inp = torch.ones((1, 2 * d), dtype=torch.float16, device="cuda")
    inp[:, :d].fill_(-1.4853515625)
    out = torch.empty((1, d), dtype=inp.dtype, device=inp.device)
    aiter.gelu_and_mul_eager(out, inp)
    assert_eager_equal(out, reference(inp))


@pytest.mark.parametrize("dtype", [torch.bfloat16, torch.float16])
def test_all_input_encodings(dtype):
    # Every 16-bit encoding, not arange(..., dtype=bf16), which loses values.
    values = torch.arange(65536, dtype=torch.int32).to(torch.int16).view(dtype)
    info = torch.finfo(dtype)
    gates = torch.tensor(
        [1.0, -1.0, 0.0, -0.0, 0.1, -0.1, 0.220703125, 2.0,
         info.tiny, info.tiny * info.eps, info.max, float('inf'), -float('inf'), float('nan')], dtype=dtype,
    )
    x = values.expand(gates.numel(), -1).contiguous().cuda()
    gate = gates[:, None].expand_as(x).contiguous().cuda()
    inp = torch.cat((x, gate), dim=-1)
    out = torch.empty_like(x)
    aiter.gelu_and_mul_eager(out, inp)
    assert_eager_equal(out, reference(inp))


@pytest.mark.parametrize("dtype", [torch.bfloat16, torch.float16])
def test_report_shape(dtype):
    torch.manual_seed(20261015)
    inp = torch.randn((16384, 5248), dtype=dtype, device="cuda")
    out = torch.empty((16384, 2624), dtype=dtype, device="cuda")
    aiter.gelu_and_mul_eager(out, inp)
    assert_eager_equal(out, reference(inp))


@pytest.mark.parametrize("dtype", [torch.bfloat16, torch.float16])
@pytest.mark.parametrize("shape", [(13, 130), (1, 5248), (4, 5248), (8, 5248)])
def test_stream_and_graph_reuse(dtype, shape):
    stream = torch.cuda.Stream()
    stream.wait_stream(torch.cuda.current_stream())
    with torch.cuda.stream(stream):
        inp = torch.randn(shape, dtype=dtype, device="cuda")
        out = torch.empty((*shape[:-1], shape[-1] // 2), dtype=dtype, device="cuda")
        aiter.gelu_and_mul_eager(out, inp)  # Build before capture.
        graph = torch.cuda.CUDAGraph()
        with torch.cuda.graph(graph, stream=stream):
            aiter.gelu_and_mul_eager(out, inp)
        for seed in range(5):
            torch.manual_seed(seed)
            inp.copy_(torch.randn_like(inp))
            graph.replay()
            assert_eager_equal(out, reference(inp))
    torch.cuda.current_stream().wait_stream(stream)


@pytest.mark.parametrize("case", ["odd", "shape", "dtype", "stride", "overlap", "fp32", "cpu"])
def test_invalid_arguments(case):
    inp = torch.empty((4, 16), dtype=torch.bfloat16, device="cuda")
    out = torch.empty((4, 8), dtype=inp.dtype, device=inp.device)
    if case == "odd":
        inp = torch.empty((4, 15), dtype=inp.dtype, device=inp.device)
    elif case == "shape":
        out = out.view(2, 16)
    elif case == "dtype":
        out = out.half()
    elif case == "stride":
        inp = torch.empty((16, 4), dtype=inp.dtype, device=inp.device).T
    elif case == "overlap":
        inp = inp.flatten()
        out = inp[:32]
    elif case == "fp32":
        inp, out = inp.float(), out.float()
    elif case == "cpu":
        inp, out = inp.cpu(), out.cpu()
    with pytest.raises((RuntimeError, ValueError)):
        aiter.gelu_and_mul_eager(out, inp)


def test_torch_compile():
    def fn(inp):
        out = torch.empty_like(inp[..., : inp.shape[-1] // 2])
        aiter.gelu_and_mul_eager(out, inp)
        return out

    inp = torch.randn((4, 130), dtype=torch.bfloat16, device="cuda")
    fn(inp)
    compiled = torch.compile(fn, fullgraph=True)
    assert_eager_equal(compiled(inp), reference(inp))
