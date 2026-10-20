# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Strict native Softmax tests. Any mismatch fails the process."""
import pytest
import torch
import aiter

DTYPES = (torch.bfloat16, torch.float16, torch.float32)
TOL = {torch.float32: (1e-5, 1e-7), torch.float16: (2e-3, 1e-6),
       torch.bfloat16: (1e-2, 1e-5)}
WIDTHS = (1, 2, 7, 8, 9, 63, 64, 65, 127, 128, 129, 1023, 1025,
          2047, 2049, 4095, 4097, 8191, 8193, 16383, 16384, 16385,
          32767, 32768, 32769, 65536, 65537, 131072, 262144, 524287, 524288)
ROWS = (0, 1, 2, 7, 31, 33, 65)


def check(x, y):
    ref = torch.softmax(x, dim=-1)
    rtol, atol = TOL[x.dtype]
    torch.testing.assert_close(y, ref, rtol=rtol, atol=atol, equal_nan=True)
    assert y.shape == x.shape and y.dtype == x.dtype and y.device == x.device
    assert torch.equal(torch.isnan(y), torch.isnan(ref))
    assert torch.equal(torch.isinf(y), torch.isinf(ref))
    if x.numel() and torch.isfinite(x).all():
        assert torch.isfinite(y).all() and (y >= 0).all()
        # At large D, FP16 subnormal output rounding can move the row sum
        # away from one even for the correctly rounded FP64 reference.
        expected_sum = (torch.ones(x.shape[0], device=x.device) if x.shape[1] <= 16384
                        else ref.float().sum(-1))
        torch.testing.assert_close(y.float().sum(-1), expected_sum,
                                   rtol=rtol, atol=atol)


@pytest.mark.parametrize("dtype", DTYPES)
@pytest.mark.parametrize("i,d", list(enumerate(WIDTHS)))
def test_tail(dtype, i, d):
    b = ROWS[1 + i % (len(ROWS) - 1)]
    torch.manual_seed(31 + i)
    x = torch.randn(b, d, device="cuda", dtype=dtype)
    old = x.clone()
    out = torch.empty_like(x)
    assert aiter.softmax(x, 1, out=out) is out
    check(x, out)
    assert aiter.softmax_out(out, x) is None
    check(x, out)
    torch.testing.assert_close(x, old, rtol=0, atol=0)


@pytest.mark.parametrize("dtype", DTYPES)
@pytest.mark.parametrize("d", (1, 1024, 16384, 16385, 524288))
def test_empty(dtype, d):
    x = torch.empty(0, d, device="cuda", dtype=dtype)
    out = torch.empty_like(x)
    assert aiter.softmax(x, out=out) is out
    assert aiter.softmax_out(out, x) is None
    check(x, out)


@pytest.mark.parametrize("dtype", DTYPES)
@pytest.mark.parametrize("d", (1024, 1025, 8192, 16384, 32768, 32769, 524287, 524288))
@pytest.mark.parametrize("input_offset", (0, 1, 2, 4, 8))
@pytest.mark.parametrize("output_offset", (0, 1, 2, 4, 8))
def test_offsets(dtype, d, input_offset, output_offset):
    n = 7 * d
    src = torch.full((n + 32,), 17, device="cuda", dtype=dtype)
    dst = torch.full((n + 32,), 19, device="cuda", dtype=dtype)
    x = src[input_offset:input_offset+n].view(7, d)
    out = dst[output_offset:output_offset+n].view(7, d)
    x.normal_()
    old = src.clone()
    aiter.softmax_out(out, x)
    check(x, out)
    torch.testing.assert_close(src, old, rtol=0, atol=0)
    assert (dst[:output_offset] == 19).all()
    assert (dst[output_offset+n:] == 19).all()


@pytest.mark.parametrize("dtype", DTYPES)
def test_vector_aligned_nonzero_offsets(dtype):
    test_offsets(dtype, 8192, 16, 32)


@pytest.mark.parametrize("dtype", DTYPES)
@pytest.mark.parametrize("d", (129, 32769, 524288))
@pytest.mark.parametrize("kind", ("zero", "constant", "bias", "extreme", "tiny",
                                  "partial_inf", "negative_inf", "positive_inf", "nan"))
def test_numeric(dtype, kind, d):
    torch.manual_seed(123)
    x = torch.randn(7, d, device="cuda", dtype=dtype)
    if kind == "zero":
        x.zero_()
    elif kind == "constant":
        x.fill_(3)
    elif kind == "bias":
        x.add_(1000)
    elif kind == "extreme":
        x[:, ::2] = torch.finfo(dtype).max
        x[:, 1::2] = -torch.finfo(dtype).max
    elif kind == "tiny":
        x.fill_(-90 if dtype != torch.float16 else -16)
        x[:, 0] = 0
    elif kind == "partial_inf":
        x[:, ::2] = -float("inf")
    elif kind == "negative_inf":
        x.fill_(-float("inf"))
    elif kind == "positive_inf":
        x[:, 64] = float("inf")
    elif kind == "nan":
        x[:, 64] = float("nan")
    y = aiter.softmax(x)
    check(x, y)
    # GPU Torch's large-D implementation can flush even double tiny results;
    # use CPU FP64 as the independent numerical oracle.
    ref64 = torch.softmax(x.cpu().double(), -1)
    actual64 = y.cpu().double()
    torch.testing.assert_close(actual64, ref64, rtol=TOL[dtype][0],
                               atol=TOL[dtype][1], equal_nan=True)
    torch.testing.assert_close(actual64.sum(-1), ref64.to(dtype).double().sum(-1),
                               rtol=TOL[dtype][0], atol=TOL[dtype][1], equal_nan=True)
    if kind == "tiny":
        # Absolute tolerance alone would silently accept FTZ here.
        assert (y[:, 1:] > 0).all()
        rounded = ref64[:, 1:].to(dtype).double()
        torch.testing.assert_close(actual64[:, 1:], rounded, rtol=TOL[dtype][0], atol=0)


@pytest.mark.parametrize("dtype", DTYPES)
def test_seeds_and_fp32_large_width(dtype):
    for seed in (1, 17, 2026):
        for d in (1024, 2048, 4096, 8192, 16384):
            torch.manual_seed(seed)
            x = torch.randn(33, d, device="cuda", dtype=dtype) * 5
            check(x, aiter.softmax(x))


@pytest.mark.parametrize("dtype", DTYPES)
@pytest.mark.parametrize("d,offset", ((129, 0), (1024, 0), (1024, 1), (16384, 0),
                                     (32769, 1), (524288, 0), (524288, 1)))
def test_denormal_sweep(dtype, d, offset, record_property):
    storage = torch.empty(2 * d + offset, device="cuda", dtype=dtype)
    x = storage[offset:].view(2, d)
    low, high = (-18, -10) if dtype == torch.float16 else (-105, -79)
    x.copy_(torch.linspace(low, high, d, device="cuda", dtype=torch.float32).to(dtype))
    x[:, 0] = 0
    y = aiter.softmax(x)
    # CPU FP64 reference independently checks the platform's tiny-result path.
    reference = torch.softmax(x.cpu().double(), -1).to(dtype).double()
    got = y.cpu().double()
    assert torch.equal(got > 0, reference > 0)
    # In the subnormal range one output ULP can exceed the normal-range rtol.
    # Bound every element by rtol OR one representable output step, while the
    # independent positivity check above forbids flushing any nonzero result.
    step = {torch.float16: 2.0**-24, torch.bfloat16: 2.0**-133,
            torch.float32: 2.0**-149}[dtype]
    diff = (got - reference).abs()
    bound = torch.maximum(reference.abs() * TOL[dtype][0], torch.full_like(reference, step))
    assert (diff <= bound).all()
    subnormal = (reference > 0) & (reference < torch.finfo(dtype).tiny)
    record_property("max_subnormal_ulp", (diff[subnormal] / step).max().item())


def test_guards():
    x = torch.randn(2, 64, device="cuda")
    invalid = [
        (x, torch.empty_like(x), 0),
        (x.reshape(-1), torch.empty_like(x).reshape(-1), -1),
        (x.t(), torch.empty_like(x.t()), -1),
        (x[:, ::2], torch.empty(2, 32, device="cuda"), -1),
        (x, torch.empty(2, 65, device="cuda"), -1),
        (x, torch.empty_like(x, dtype=torch.float16), -1),
        (x, torch.empty_like(x, device="cpu"), -1),
        (x, torch.empty(64, 2, device="cuda").t(), -1),
        (x, x, -1),
        (torch.empty(2, 0, device="cuda"), torch.empty(2, 0, device="cuda"), -1),
        (torch.empty(2, 524289, device="cuda"), torch.empty(2, 524289, device="cuda"), -1),
        (x.double(), x.double(), -1),
        (x.cpu(), x.cpu(), -1),
    ]
    backing = torch.empty(129, device="cuda")
    invalid.append((backing[:128].view(2, 64), backing[1:].view(2, 64), -1))
    for src, out, dim in invalid:
        with pytest.raises((RuntimeError, ValueError, TypeError)):
            aiter.softmax(src, dim, out=out)
        with pytest.raises((RuntimeError, ValueError, TypeError)):
            aiter.softmax_out(out, src, dim)
    # Same allocation, disjoint intervals are valid.
    backing = torch.randn(256, device="cuda")
    src, out = backing[:128].view(2, 64), backing[128:].view(2, 64)
    aiter.softmax_out(out, src)
    check(src, out)


def test_autograd():
    x = torch.randn(2, 64, device="cuda", requires_grad=True)
    out = torch.empty_like(x)
    for op in (lambda: aiter.softmax(x), lambda: aiter.softmax_out(out, x)):
        with pytest.raises(RuntimeError, match="forward-only"):
            op()
    with torch.no_grad():
        check(x, aiter.softmax(x))
        aiter.softmax_out(out, x)
        check(x, out)
    with torch.inference_mode():
        check(x, aiter.softmax(x))


@pytest.mark.parametrize("dtype", DTYPES)
@pytest.mark.parametrize("d", (1025, 8192, 32769, 524288))
def test_stream_graph(dtype, d):
    stream = torch.cuda.Stream()
    x = torch.empty(33, d, device="cuda", dtype=dtype)
    out = torch.empty_like(x)
    stream.wait_stream(torch.cuda.current_stream())
    with torch.cuda.stream(stream):
        x.normal_()
        aiter.softmax_out(out, x)
    torch.cuda.current_stream().wait_stream(stream)
    check(x, out)
    graph = torch.cuda.CUDAGraph()
    with torch.cuda.graph(graph, stream=stream):
        aiter.softmax_out(out, x)
    for seed in (12, 23, 34):
        torch.manual_seed(seed)
        x.normal_()
        graph.replay()
        check(x, out)


@pytest.mark.parametrize("dtype", DTYPES)
@pytest.mark.parametrize("d", (129, 8192, 32769, 524288))
def test_compile(dtype, d):
    x = torch.randn(7, d, device="cuda", dtype=dtype)
    out = torch.empty_like(x)
    # Warm JIT before compilation/capture.
    aiter.softmax_out(out, x)
    allocating = torch.compile(lambda t: aiter.softmax(t), fullgraph=True)
    preallocated = torch.compile(lambda t, o: aiter.softmax(t, out=o), fullgraph=True)
    def mutation(t, o):
        aiter.softmax_out(o, t)
        return o
    mutating = torch.compile(mutation, fullgraph=True)
    for seed in (14, 25, 36):
        torch.manual_seed(seed)
        x.normal_()
        old = x.clone()
        check(x, allocating(x))
        assert preallocated(x, out) is out
        check(x, out)
        assert mutating(x, out) is out
        check(x, out)
        torch.testing.assert_close(x, old, rtol=0, atol=0)


@pytest.mark.parametrize("d", (129, 16385, 524288))
def test_meta(d):
    x = torch.empty(7, d, device="meta")
    out = torch.empty_like(x)
    assert aiter.softmax(x, out=out) is out
    assert aiter.softmax_out(out, x) is None
    assert aiter.softmax(x).shape == x.shape
    bad = torch.empty(0, 524289, device="meta")
    with pytest.raises(ValueError, match="524288"):
        aiter.softmax(bad)
    with pytest.raises(ValueError, match="524288"):
        aiter.softmax_out(torch.empty_like(bad), bad)
