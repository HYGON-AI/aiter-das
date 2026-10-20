"""CAR collectives, fused operators, transport and input reuse contracts at TP2/4/8.

Run with python and no arguments for the TP2 + TP4 CI matrix.
AITER_AR_TP_SIZE limits the default matrix to the CI GPU allocation (2 or 4).
TP8 requires explicit --tp-size 8 or torchrun. Explicit torchrun accepts one --suite.
"""
import argparse
from datetime import timedelta
import hashlib
import json
import os
from pathlib import Path
import signal
import subprocess
import sys
import tempfile
import time
from unittest.mock import patch
from types import SimpleNamespace


def load_worker_runtime():
    # Keep --help/--dry-run and launcher checks usable without torch or a GPU.
    global torch, dist, CustomAllreduce, car, ops, native
    global fp8_table, fp8_encode_oracle, int8_wrap
    import torch
    import torch.distributed as dist
    from aiter.dist.device_communicators.custom_all_reduce import CustomAllreduce
    from aiter.dist.device_communicators import custom_all_reduce as car
    from aiter.ops import custom_all_reduce as ops
    from aiter.ops import custom_all_reduce as native
    sys.path.insert(0, str(Path(__file__).resolve().parents[1] / 'multigpu_tests'))
    from collective_reference import fp8_table, fp8_encode_oracle, int8_wrap


def expect_value_error(fn):
    try:
        fn()
    except ValueError:
        return
    raise AssertionError("expected an input validation error before launching a kernel")


def run_collectives(args):
    from aiter.dist.device_communicators.communicator_cuda import CudaCommunicator
    rank = int(os.environ["RANK"])
    local = int(os.environ["LOCAL_RANK"])
    world = int(os.environ["WORLD_SIZE"])
    torch.cuda.set_device(local)
    dist.init_process_group("gloo", timeout=timedelta(seconds=120))
    ca = None
    cases = 0
    rejected_fp8_checks = 0
    fallback_rejections = 0
    try:
        for register in (False, True):
            ca = CustomAllreduce(dist.group.WORLD, local, max_size=16 * 1024 * 1024,
                                 enable_register_for_capturing=register)
            assert not ca.disabled and ca.transport == args.transport
            if args.transport == "fabric":
                assert not ca.enable_register_for_capturing
            for dtype in (torch.float32, torch.float16, torch.bfloat16):
                for shape, dim in [((world * 2, 64), 0), ((3, world * 16), -1),
                                   ((8, world * 3), -1), ((2, world * 3, 16), 1),
                                   ((8, world * 2, 3), 1), ((2, world * 2, 3, 8), 1)]:
                    base = torch.arange(torch.tensor(shape).prod().item(), device=local,
                                        dtype=torch.float32).reshape(shape).remainder(7) * .125
                    inp = (base + rank).to(dtype)
                    outshape = list(shape)
                    outshape[dim] //= world
                    out = torch.empty(outshape, device=local, dtype=dtype)
                    assert ca.should_custom_rs(inp, dim)
                    ca.custom_reduce_scatter(inp, out, dim=dim)
                    reference = sum((base + r).to(dtype).float() for r in range(world)).to(dtype)
                    torch.testing.assert_close(out, reference.chunk(world, dim=dim)[rank], rtol=0, atol=0)
                    with ca.capture():
                        # The warmup result is consumed; returning zeros/None without a write fails.
                        out.fill_(float('nan'))
                        ca.custom_reduce_scatter(inp, out, dim=dim)
                        torch.testing.assert_close(out, reference.chunk(world, dim=dim)[rank], rtol=0, atol=0)
                        graph = torch.cuda.CUDAGraph()
                        with torch.cuda.graph(graph):
                            ca.custom_reduce_scatter(inp, out, dim=dim)
                    for i in range(args.repeats):
                        inp.copy_((base + rank + (i % 8) * .125).to(dtype))
                        graph.replay()
                        reference = sum((base + r + (i % 8) * .125).to(dtype).float() for r in range(world)).to(dtype)
                        torch.testing.assert_close(out, reference.chunk(world, dim=dim)[rank], rtol=0, atol=0, msg=f"RS register={register} dtype={dtype} shape={shape} dim={dim} replay={i} rank={rank}")
                    cases += 1
                    del graph
            for dtype in (torch.int8, *car.FP8_DTYPES):
                for shape, dim in [((world * 16, 16), 0), ((16, world * 3), -1),
                                   ((16, world * 3, 3), 1)]:
                    base = torch.arange(torch.tensor(shape).prod().item()).reshape(shape) % 7
                    def rs_value(r, iteration):
                        return (base + r + iteration + (100 if dtype == torch.int8 else 0)).to(dtype)
                    def rs_expected(iteration):
                        values = [rs_value(r, iteration) for r in range(world)]
                        if dtype == torch.int8:
                            acc = sum(v.to(torch.int32) for v in values)
                            result = int8_wrap(acc.chunk(world, dim)[rank].contiguous())
                        else:
                            table = fp8_table(dtype)[0]
                            acc = sum(table[v.view(torch.uint8).long()] for v in values)
                            result = fp8_encode_oracle(acc.chunk(world, dim)[rank].contiguous(), dtype)
                        return result.view(torch.uint8)
                    inp = rs_value(rank, 0).to(local)
                    out = torch.empty_like(rs_expected(0), device=local).view(dtype)
                    ca.reduce_scatter(inp, out, dim)
                    torch.testing.assert_close(out.view(torch.uint8).cpu(), rs_expected(0), rtol=0, atol=0)
                    with ca.capture():
                        graph = torch.cuda.CUDAGraph()
                        with torch.cuda.graph(graph):
                            ca.custom_reduce_scatter(inp, out, dim)
                            inp.view(torch.uint8).fill_(0xA5)
                    for i in range(args.repeats):
                        inp.view(torch.uint8).copy_(rs_value(rank, i % 8).view(torch.uint8))
                        graph.replay()
                        torch.testing.assert_close(out.view(torch.uint8).cpu(), rs_expected(i % 8), rtol=0, atol=0)
                    cases += 1
                    del graph
            for dtype in (torch.float32, torch.float16, torch.bfloat16,
                          torch.int16, torch.int32, torch.int64):
                for dim in (0, -1):
                    base = torch.arange(128, device=local).reshape(4, 32)
                    # int32 includes NaN bit patterns when viewed as fp32; int64
                    # includes high words that a numerical float cast would lose.
                    offset = (1 << 40) if dtype == torch.int64 else (0x7fc00000 if dtype == torch.int32 else 0)
                    def rank_input(r, i):
                        return (base + offset + r * 128 + i).to(dtype)
                    inp = rank_input(rank, 0)
                    expected = torch.cat([rank_input(r, 0) for r in range(world)], dim=dim)
                    out = torch.empty_like(expected)
                    assert ca.all_gather_unreg(inp, out=out, dim=dim) is out
                    torch.testing.assert_close(out, expected, rtol=0, atol=0)
                    with ca.capture():
                        torch.testing.assert_close(ca.custom_all_gather(inp, dim), expected, rtol=0, atol=0)
                        graph = torch.cuda.CUDAGraph()
                        with torch.cuda.graph(graph):
                            result = ca.custom_all_gather(inp, dim)
                    for i in range(args.repeats):
                        inp.copy_(rank_input(rank, i % 8))
                        graph.replay()
                        expected = torch.cat([rank_input(r, i % 8) for r in range(world)], dim=dim)
                        torch.testing.assert_close(result, expected, rtol=0, atol=0)
                    cases += 1
                    del graph, result
            for dtype in (torch.int8, torch.uint8, *car.FP8_DTYPES):
                for dim in (0, -1):
                    base = torch.arange(256, device=local).reshape(8, 32)
                    def rank_bytes(r, i):
                        return ((base + 37 * r + 19 * i) % 256).to(torch.uint8)
                    inp = rank_bytes(rank, 0).view(dtype)
                    expected = torch.cat([rank_bytes(r, 0) for r in range(world)], dim=dim)
                    out = torch.empty_like(expected).view(dtype)
                    assert ca.all_gather_unreg(inp, out=out, dim=dim) is out
                    torch.testing.assert_close(out.view(torch.uint8), expected, rtol=0, atol=0)
                    with ca.capture():
                        warm = ca.custom_all_gather(inp, dim)
                        torch.testing.assert_close(warm.view(torch.uint8), expected, rtol=0, atol=0)
                        graph = torch.cuda.CUDAGraph()
                        with torch.cuda.graph(graph):
                            result = ca.custom_all_gather(inp, dim)
                            inp.view(torch.uint8).fill_(0xA5)
                    for i in range(args.repeats):
                        inp.view(torch.uint8).copy_(rank_bytes(rank, i))
                        graph.replay()
                        expected = torch.cat([rank_bytes(r, i) for r in range(world)], dim=dim)
                        torch.testing.assert_close(result.view(torch.uint8), expected, rtol=0, atol=0)
                    cases += 1
                    del graph, result, warm
            # Hygon excludes FNUZ, even when Torch exposes these storage dtypes.
            for name in ("float8_e4m3fnuz", "float8_e5m2fnuz"):
                dtype = getattr(torch, name, None)
                if dtype is None:
                    continue
                assert dtype not in car.FP8_DTYPES
                inp = torch.zeros((world * 16, 16), device=local, dtype=torch.uint8).view(dtype)
                for dim in (0, -1):
                    rs_shape, ag_shape = list(inp.shape), list(inp.shape)
                    rs_shape[dim] //= world
                    ag_shape[dim] *= world
                    rs_out = torch.full(rs_shape, 0xA5, device=local, dtype=torch.uint8).view(dtype)
                    ag_out = torch.full(ag_shape, 0xA5, device=local, dtype=torch.uint8).view(dtype)
                    assert not ca.should_custom_rs(inp, dim)
                    assert ca.custom_reduce_scatter(inp, rs_out, dim) is None
                    expect_value_error(lambda: ca.reduce_scatter(inp, rs_out, dim))
                    assert not ca.should_custom_ag(inp, dim)
                    assert ca.custom_all_gather(inp, dim) is None
                    expect_value_error(lambda: ca.all_gather_unreg(inp, out=ag_out, dim=dim))
                    expect_value_error(lambda: ca.all_gather_reg(inp, out=ag_out, dim=dim))
                    assert (rs_out.view(torch.uint8) == 0xA5).all().item()
                    assert (ag_out.view(torch.uint8) == 0xA5).all().item()
                    rejected_fp8_checks += 1
            raw_inp = torch.zeros(world * 16, device=local, dtype=torch.uint8)
            raw_out = torch.full((16,), 0xA5, device=local, dtype=torch.uint8)
            for removed_format in (2, 4):
                expect_value_error(lambda: ops.reduce_scatter_8bit(
                    ca._ptr, raw_inp, raw_out, 0, 0, raw_inp.numel(), 0,
                    ca._pool['input'].data_ptr, ca._pool['input'].max_size, removed_format))
                assert (raw_out == 0xA5).all().item()
                rejected_fp8_checks += 1
            # Unsupported FP8 must fail before RCCL; a disabled fallback must
            # never cause the public method to return an unwritten output.
            public = object.__new__(CudaCommunicator)
            public.world_size, public.ca_comm = world, ca
            def unexpected_fallback(*unused):
                raise AssertionError('unsupported fallback reached RCCL')
            public.pynccl_comm = SimpleNamespace(disabled=False, reduce_scatter=unexpected_fallback)
            old_size = ca.max_size
            ca.max_size = 16
            try:
                for dtype in (*car.FP8_DTYPES, torch.float8_e4m3fnuz, torch.float8_e5m2fnuz):
                    inp = torch.empty((world * 16, world * 16), dtype=dtype, device=local)
                    for dim in (0, -1):
                        expect_value_error(lambda: public.reduce_scatter(inp, dim))
                        fallback_rejections += 1
            finally:
                ca.max_size = old_size
            public.ca_comm = None
            for backend in (None, SimpleNamespace(disabled=True, reduce_scatter=unexpected_fallback)):
                public.pynccl_comm = backend
                for dtype in (torch.int8, torch.float16, torch.bfloat16, torch.float32):
                    inp = torch.empty(world * 16, dtype=dtype, device=local)
                    try:
                        public.reduce_scatter(inp, 0)
                    except RuntimeError as exc:
                        assert 'active RCCL' in str(exc)
                    else:
                        raise AssertionError('inactive fallback must fail')
                    fallback_rejections += 1
            x = torch.ones((world * 2, 64), device=local)
            y = torch.empty((2, 64), device=local)
            assert not ca.should_custom_rs(x, 5)
            assert not ca.should_custom_rs(x.t(), 0)
            assert not ca.should_custom_rs(x.to(torch.int32), 0)
            assert not ca.should_custom_rs(torch.ones(2, 64), 0)
            expect_value_error(lambda: ca.reduce_scatter(x, torch.empty_like(x), 0))
            expect_value_error(lambda: ca.reduce_scatter(x, x[:2], 0))
            expect_value_error(lambda: ca.all_gather_unreg(x, out=y))
            expect_value_error(lambda: ca.all_gather_unreg(x.unsqueeze(0), dim=1))
            assert ca.custom_all_gather(x.unsqueeze(0), dim=1) is None
            big = torch.empty((world * 4, 64), device=local)
            expect_value_error(lambda: ca.all_gather_unreg(big[:4], out=big))
            # Original low-level ABI remains callable alongside the dimension entry.
            ops.reduce_scatter(ca._ptr, x, y, ca._pool['input'].data_ptr, ca._pool['input'].max_size)
            torch.testing.assert_close(y, torch.full_like(y, world), rtol=0, atol=0)
            torch.cuda.synchronize()
            dist.barrier()
            ca.close()
            ca.close()
            assert ca._ptr == 0 and not ca._pool._buffers and ca.disabled
            del ca
            ca = None
        for _ in range(args.close_repeats):
            ca = CustomAllreduce(dist.group.WORLD, local, max_size=1024 * 1024,
                                 enable_register_for_capturing=False)
            assert not ca.disabled
            x = torch.full((2, 64), rank + 1., device=local)
            out = ca.custom_all_reduce(x)
            assert out is not None
            torch.testing.assert_close(out, torch.full_like(out, world * (world + 1) / 2), rtol=0, atol=0)
            torch.cuda.synchronize()
            dist.barrier()
            ca.close()
            ca = None
        print('COMM_SYNC_CONTRACT_PASS ' + json.dumps(dict(rank=rank, world=world,
              cases=cases, rejected_fp8_checks=rejected_fp8_checks,
              fallback_rejections=fallback_rejections,
              replays=args.repeats, close_repeats=args.close_repeats,
              arch=torch.cuda.get_device_properties(local).gcnArchName,
              transport=args.transport, ag_rs_copy_in=ops.ag_rs_requires_copy_in())), flush=True)
    finally:
        if ca is not None:
            ca.close()
        dist.destroy_process_group()


def check(actual, expected, dtype, label):
    assert torch.isfinite(actual.float()).all(), label
    # Predeclared for reductions with production-dtype rounding. Quantization
    # error is tested separately from the unquantized norm and residual.
    tol = 0.025 if dtype == torch.bfloat16 else 0.003
    torch.testing.assert_close(actual.float(), expected.float(), rtol=tol, atol=tol, msg=label)


def expect_error(fn):
    try:
        fn()
    except ValueError:
        return
    raise AssertionError("expected validation failure before launch")


def run_fusions(args):
    rank, local, world = [int(os.environ[k]) for k in ('RANK', 'LOCAL_RANK', 'WORLD_SIZE')]
    torch.cuda.set_device(local)
    device = torch.device('cuda', local)
    dist.init_process_group('gloo', timeout=timedelta(seconds=180))
    count = 0
    ca = None
    modes = [False, True] if args.register == 'both' else [args.register == 'on']
    try:
        for register in modes:
            ca = CustomAllreduce(dist.group.WORLD, device, max_size=32 * 1024 * 1024,
                                 enable_register_for_capturing=register)
            assert not ca.disabled
            for dtype in (torch.float16, torch.bfloat16):
                # norm, Gemma, padded storage/output, packed strided input,
                # per-token mirror, per-group mirror and scale strides.
                cases = [('norm', 512, False), ('gemma', 2880, True),
                         ('pad', 2048, False), ('packed', 512, True),
                         ('token', 2048, True), ('token', 8192, False),
                         ('group', 2048, True), ('transpose', 8192, False),
                         ('token_split', 8192, False), ('group_split', 8192, False),
                         ('norm', 16384, False)]
                for kind, width, one_stage in cases:
                    tokens = 64 if kind.endswith("_split") else 4
                    kind = kind.removesuffix("_split")
                    storage_width = width + 16 if kind in ('pad', 'packed') else width
                    storage = torch.empty((tokens, storage_width), device=device, dtype=dtype)
                    inp = storage[:, :width] if kind == 'packed' else storage
                    base = (torch.arange(tokens * width, device=device).reshape(tokens, width) % 17 - 8).float() / 16
                    residual = torch.empty_like(base, dtype=dtype)
                    weight = ((torch.arange(width, device=device) % 7).float() / 8 + .5).to(dtype)
                    eps = 1e-6
                    gemma = kind == 'gemma'

                    def fill(iteration):
                        delta = (iteration % 4) / 16
                        storage.fill_(7)
                        storage[:, :width].copy_((base + rank / 8 + delta).to(dtype))
                        residual.fill_(.125 + (iteration % 3) / 16)
                        summed = sum((base + r / 8 + delta).to(dtype).float() for r in range(world)).to(dtype).float()
                        z = summed + residual.float()
                        norm = z * torch.rsqrt(z.square().mean(-1, keepdim=True) + eps)
                        norm *= weight.float() + (1 if gemma else 0)
                        return z, norm

                    def invoke():
                        if kind in ('group', 'transpose'):
                            return ca.custom_fused_ar_rms_per_group_quant(inp, residual, weight, eps,
                                group_size=128, use_1stage=one_stage, emit_bf16=True,
                                transpose_scale=kind == 'transpose')
                        if kind == 'token':
                            return ca.custom_fused_ar_rms_quant(inp, residual, weight, eps,
                                use_1stage=one_stage, gemma_norm=False, emit_bf16=True)
                        if kind == 'packed':
                            return ca.custom_fused_ar_rms_packed_input(inp, residual, weight, eps,
                                use_1stage=one_stage)
                        return ca.custom_fused_ar_rms(inp, residual, weight, eps,
                            use_1stage=one_stage, out_hidden_dim=width + 32 if kind == 'pad' else 0,
                            gemma_norm=gemma)

                    def validate(outputs, z, norm, label):
                        assert outputs is not None, label
                        check(outputs[1], z.to(dtype), dtype, label + '/residual')
                        if kind in ('token', 'group', 'transpose'):
                            quant, _, scales, mirror = outputs
                            assert quant.dtype == torch.float8_e4m3fn and mirror.dtype == dtype
                            check(mirror, norm.to(dtype), dtype, label + '/mirror')
                            groups = 1 if kind == 'token' else width // 128
                            expected_scale = norm.reshape(tokens, groups, -1).abs().amax(-1) / 448
                            expected_scale = torch.where(expected_scale == 0, torch.ones_like(expected_scale), expected_scale)
                            check(scales, expected_scale, dtype, label + '/scale')
                            assert tuple(scales.shape) == (tokens, groups)
                            if kind == 'transpose':
                                assert scales.stride() == (1, tokens)
                            dequant = quant.float().reshape(tokens, groups, -1) * scales.unsqueeze(-1)
                            # One half FP8 step plus production dtype rounding.
                            torch.testing.assert_close(dequant.reshape_as(norm), norm,
                                                       rtol=.10, atol=.03, msg=label + '/dequant')
                        else:
                            check(outputs[0][:, :width], norm.to(dtype), dtype, label + '/norm')
                            if kind == 'pad':
                                assert outputs[0].shape == (tokens, width + 32)
                                assert torch.count_nonzero(outputs[0][:, width:]) == 0

                    z, norm = fill(0)
                    validate(invoke(), z, norm, f'eager/{kind}/{tokens}x{width}/{dtype}/{register}')
                    with ca.capture():
                        invoke()
                        graph = torch.cuda.CUDAGraph()
                        with torch.cuda.graph(graph):
                            outputs = invoke()
                    for i in range(args.repeats):
                        z, norm = fill(i)
                        graph.replay()
                        validate(outputs, z, norm, f'graph/{kind}/{tokens}x{width}/{dtype}/{register}/{i}')
                    del graph, outputs
                    count += 1

                # Exact E2M1 ties, signs, packing order and E8M0 scale. A sum of
                # exactly one with eps=0 makes normalized values equal weight.
                width = 512
                values = torch.tensor([0, .25, .5, .75, 1, 1.25, 1.5, 1.75,
                                       2, 2.5, 3, 3.5, 4, 5, 6, -6], device=device)
                weight = values.repeat(width // 16).to(dtype)
                x = torch.full((4, width), 1 / world, device=device, dtype=dtype)
                residual = torch.zeros_like(x)
                bounds = torch.tensor([.25, .75, 1.25, 1.75, 2.5, 3.5, 5], device=device)
                codes = torch.bucketize(weight.float().abs(), bounds, right=True).to(torch.uint8)
                codes |= (weight < 0).to(torch.uint8) << 3
                packed = codes[::2] | (codes[1::2] << 4)
                for one_stage in (False, True):
                    result = ca.custom_fused_ar_rms_mxfp4_quant(x, residual, weight, 0.,
                        use_1stage=one_stage, emit_bf16=True)
                    assert result[0].dtype == result[2].dtype == torch.uint8
                    torch.testing.assert_close(result[0], packed.expand(4, -1), rtol=0, atol=0)
                    torch.testing.assert_close(result[2], torch.full_like(result[2], 127), rtol=0, atol=0)
                    check(result[3], weight.expand_as(x), dtype, 'mxfp4/mirror')
                    with ca.capture():
                        graph = torch.cuda.CUDAGraph()
                        with torch.cuda.graph(graph):
                            result = ca.custom_fused_ar_rms_mxfp4_quant(x, residual, weight, 0.,
                                use_1stage=one_stage, emit_bf16=True)
                    for i in range(args.repeats):
                        # Powers of two make rsqrt normalization exact at E2M1
                        # ties. For a sum of 3, rsqrtf(9)*3 is slightly below
                        # one, legitimately mapping every tie to the lower bin.
                        x.fill_((2 ** (i % 4)) / world)
                        graph.replay()
                        torch.testing.assert_close(result[0], packed.expand(4, -1), rtol=0, atol=0)
                        torch.testing.assert_close(result[2], torch.full_like(result[2], 127), rtol=0, atol=0)
                        check(result[1], torch.full_like(x, 2 ** (i % 4)), dtype, 'mxfp4/residual')
                        check(result[3], weight.expand_as(x), dtype, 'mxfp4/mirror')
                    del graph, result
                    count += 1
                # Zero input has zero E2M1 payload and the upstream E8M0 zero scale.
                x.zero_()
                zero = ca.custom_fused_ar_rms_mxfp4_quant(x, residual, weight, 1e-6, emit_bf16=True)
                assert all(torch.count_nonzero(t) == 0 for t in zero)
                # Exact E4M3FN encoding (ties-to-even, signs, subnormals, max).
                f8 = torch.tensor([0, 2**-10, 2**-9, 3*2**-10, .25, 1.0625, 1.1875,
                                   1.25, 16, 240, 448, -448, -1.0625, -2**-9, 2, -2], device=device)
                f8w = f8.repeat(width // 16).to(dtype)
                x.fill_(1 / world)
                f8out = ca.custom_fused_ar_rms_quant(x, residual, f8w, 0., use_1stage=True, emit_bf16=True)
                torch.testing.assert_close(f8out[0].view(torch.uint8),
                    f8w.to(torch.float8_e4m3fn).view(torch.uint8).expand_as(x), rtol=0, atol=0)
                torch.testing.assert_close(f8out[2], torch.ones_like(f8out[2]), rtol=0, atol=0)
                # Existing QK uses global statistics, but preserves local Q/K/V.
                qkv = torch.empty((4, 768), dtype=dtype, device=device)
                qw = torch.ones(256, dtype=dtype, device=device)
                kw = torch.full_like(qw, .5)
                qbase = (torch.arange(qkv.numel(), device=device).reshape(qkv.shape) % 13 - 6).float() / 8
                def fill_qk(i):
                    all_inputs = [(qbase + r / 8 + (i % 4) / 16).to(dtype) for r in range(world)]
                    qkv.copy_(all_inputs[rank])
                    ref = []
                    for start, w in ((0, qw), (256, kw)):
                        variance = torch.stack([t[:, start:start+256].float().square().mean(-1, keepdim=True) for t in all_inputs]).mean(0)
                        ref.append(qkv[:, start:start+256].float() * torch.rsqrt(variance + 1e-6) * w.float())
                    return (*ref, qkv[:, 512:])
                expected = fill_qk(0)
                for got, want in zip(ca.custom_fused_qknorm_ar(qkv, qw, kw, 1e-6), expected):
                    check(got, want, dtype, 'qk/eager')
                with ca.capture():
                    graph = torch.cuda.CUDAGraph()
                    with torch.cuda.graph(graph):
                        qko = ca.custom_fused_qknorm_ar(qkv, qw, kw, 1e-6)
                for i in range(args.repeats):
                    expected = fill_qk(i)
                    graph.replay()
                    for got, want in zip(qko, expected):
                        check(got, want, dtype, 'qk/graph')
                del graph, qko
                count += 3
                # The exported native API must reject bad metadata before copy/launch.
                expect_error(lambda: native.fused_allreduce_rmsnorm(0, x, residual,
                    torch.empty_like(x), torch.empty_like(x), weight, 1e-6,
                    ca._pool["input"].data_ptr, ca._pool["input"].max_size, False))
                expect_error(lambda: native.fused_allreduce_rmsnorm(ca._ptr, x, residual,
                    torch.empty_like(x, dtype=torch.float32), torch.empty_like(x), weight, 1e-6,
                    ca._pool["input"].data_ptr, ca._pool["input"].max_size, False))
                expect_error(lambda: ca.fused_ar_rms(x, residual, w=weight, eps=1e-6, out_hidden_dim=32))
                expect_error(lambda: ca.fused_ar_rms_per_group_quant(x, residual, w=weight, eps=1e-6, group_size=31))
            torch.cuda.synchronize()
            dist.barrier()
            ca.close()
            ca = None
        print('COMM_FUSION_CONTRACT_PASS ' + json.dumps(dict(rank=rank, world=world,
            cases=count, replays=args.repeats, fused_copy_in=native.ag_rs_requires_copy_in(), arch=torch.cuda.get_device_properties(local).gcnArchName)), flush=True)
    finally:
        if ca is not None:
            ca.close()
        dist.destroy_process_group()


def run_transport(args):
    rank,local,world=[int(os.environ[k]) for k in ('RANK','LOCAL_RANK','WORLD_SIZE')]
    torch.cuda.set_device(local);device=torch.device('cuda',local)
    dist.init_process_group('gloo',timeout=timedelta(seconds=120))
    ca=None
    try:
        os.environ['AITER_AR_TRANSPORT']='auto'
        ca=car.CustomAllreduce(dist.group.WORLD,device,max_size=16*1024*1024,enable_register_for_capturing=False)
        assert not ca.disabled and ca.transport=='ipc'
        for dtype in (torch.float16,torch.bfloat16,torch.float32):
            x=torch.empty((4,512),device=device,dtype=dtype)
            x.fill_(rank+1)
            y=ca.custom_all_reduce(x)
            torch.testing.assert_close(y,torch.full_like(y,sum(range(1,world+1))),rtol=0,atol=0)
            with ca.capture():
                graph=torch.cuda.CUDAGraph()
                with torch.cuda.graph(graph):y=ca.custom_all_reduce(x)
            for step in range(100):
                x.fill_(rank+1+(step%4)/8);graph.replay()
                torch.testing.assert_close(y,torch.full_like(y,sum(range(1,world+1))+world*(step%4)/8),rtol=0,atol=0)
            del graph,y
        torch.cuda.synchronize();dist.barrier();ca.close();ca.close();ca=None
        if args.tp6:
            print('CAR_TP6_PASS',rank,world,flush=True)
            return
        # Inject one failed rank at three native resource phases; all ranks
        # must leave initialization disabled and release their allocations.
        os.environ['AITER_AR_TRANSPORT']='ipc'
        for owner,method in ((car.IPCBufferPool,'create'),(car.IPCBufferPool,'get_local_meta'),(car.ops,'init_custom_ar')):
            original=getattr(owner,method)
            def injected(*a,**kw):
                if rank==0:raise RuntimeError('injected '+method)
                return original(*a,**kw)
            with patch.object(owner,method,injected):
                ca=car.CustomAllreduce(dist.group.WORLD,device,max_size=1024*1024)
            assert ca.disabled and ca._ptr==0
            ca.close();assert not ca._pool._buffers;ca=None
            dist.barrier()
            print('CAR_INIT_FAILURE_PASS',rank,method,flush=True)
        if world>2:
            with patch.object(car,'is_fully_connected',return_value=False):
                ca=car.CustomAllreduce(dist.group.WORLD,device,max_size=1024*1024)
            assert ca.disabled;ca.close();ca=None
        if args.fabric_disabled:
            os.environ['AITER_AR_TRANSPORT']='fabric'
            try:car.CustomAllreduce(dist.group.WORLD,device,max_size=1024*1024)
            except RuntimeError as exc:assert 'not compiled' in str(exc)
            else:raise AssertionError('disabled build admitted Fabric')
        print('TRANSPORT_CONTRACTS_PASS',json.dumps({'rank':rank,'world':world,
              'fabric_build':bool(car.ops.fabric_ar_available()),'copyin':bool(car.ops.ag_rs_requires_copy_in())}),flush=True)
    finally:
        if ca is not None:ca.close()
        dist.destroy_process_group()



def run_reuse_case(ca, args, dtype, numel, mode):
    rank, world = dist.get_rank(), dist.get_world_size()
    inp = torch.empty(numel, device=ca.device, dtype=dtype)
    seed = torch.empty_like(inp)
    # Dyadic fractions plus small integers are exactly representable in BF16.
    base = (torch.arange(numel, device=ca.device) % 8).to(dtype) / 8

    def chain():
        inp.copy_(seed)
        outputs = []
        for _ in range(args.depth):
            out = ca.custom_all_reduce(inp, use_new=not args.legacy)
            if out is None:
                raise RuntimeError("custom allreduce unexpectedly fell back")
            outputs.append(out)
            inp.add_(1)
        return outputs

    seed.copy_(base + rank)
    chain()
    torch.cuda.synchronize()
    dist.barrier()
    graph = None
    if mode == "graph":
        graph = torch.cuda.CUDAGraph()
        with ca.capture():
            with torch.cuda.graph(graph):
                outputs = chain()
    mismatch = 0
    max_error = 0.0
    first = None
    for replay in range(args.repeats):
        shift = replay % 4
        seed.copy_(base + rank + shift)
        # Synchronize only before the chain, never between AR and input reuse.
        torch.cuda.synchronize()
        dist.barrier()
        if graph is None:
            outputs = chain()
        else:
            graph.replay()
        torch.cuda.synchronize()
        for step, out in enumerate(outputs):
            expected = (base.float() * world + world * (shift + step)
                        + world * (world - 1) / 2).to(dtype)
            count = int(torch.count_nonzero(out != expected))
            if count:
                mismatch += count
                max_error = max(max_error, float((out.float() - expected.float()).abs().max()))
                if first is None:
                    first = {"replay": replay, "step": step,
                             "actual_head": out[:8].float().cpu().tolist(),
                             "expected_head": expected[:8].float().cpu().tolist()}
    result = dict(rank=rank, world=world, dtype=str(dtype), numel=numel,
                  mode=mode, requested_registered=bool(args.registered),
                  registered=ca.enable_register_for_capturing,
                  legacy=args.legacy, repeats=args.repeats, depth=args.depth,
                  mismatches=mismatch, max_error=max_error, first_failure=first)
    print("AR_REUSE_RESULT " + json.dumps(result), flush=True)
    dist.barrier()
    return int(mismatch != 0)



def run_reuse(args):
    local = int(os.environ["LOCAL_RANK"])
    torch.cuda.set_device(local)
    os.environ["AITER_AR_TRANSPORT"] = "ipc"
    dist.init_process_group("gloo", timeout=timedelta(seconds=180))
    ca = None
    try:
        ca = CustomAllreduce(dist.group.WORLD, local, max_size=8 * 1024 * 1024,
                             enable_register_for_capturing=True)
        assert not ca.disabled and ca.transport == "ipc"
        arch = torch.cuda.get_device_properties(local).gcnArchName.split(":")[0]
        if arch in ("gfx936", "gfx938"):
            assert not ca.enable_register_for_capturing
        # Exact dyadic sums detect peer reads racing the next staging copy.
        case_args = argparse.Namespace(registered=1, legacy=False,
                                       repeats=args.repeats, depth=8)
        failures = 0
        for dtype in (torch.bfloat16, torch.float16, torch.float32):
            for numel in (2048, 12288, 98304, 1048576):
                for mode in ("eager", "graph"):
                    failures += run_reuse_case(ca, case_args, dtype, numel, mode)
        counts = [None] * dist.get_world_size()
        dist.all_gather_object(counts, failures)
        assert not any(counts), f"input reuse failures per rank: {counts}"
    finally:
        if ca is not None:
            ca.close()
        dist.destroy_process_group()


def run_ar_boundaries(args):
    """Mixed sizes, two live graphs, allocator reuse and rank submission skew."""
    local = int(os.environ['LOCAL_RANK'])
    torch.cuda.set_device(local)
    os.environ['AITER_AR_TRANSPORT'] = 'ipc'
    dist.init_process_group('gloo', timeout=timedelta(seconds=180))
    rank, world = dist.get_rank(), dist.get_world_size()
    ca = None
    try:
        ca = CustomAllreduce(dist.group.WORLD, local, max_size=64 << 20,
                             enable_register_for_capturing=True)
        assert not ca.disabled and ca.transport == 'ipc'
        requested = os.environ.get('AITER_AR_SMALL_MESSAGE', 'off')
        if requested != 'off':
            assert ca.small_ar_mode == requested, (ca.small_ar_mode, requested)
        empty = torch.empty(0, device='cuda', dtype=torch.float16)
        assert not ca.should_custom_ar(empty)
        expect_value_error(lambda: ca.all_reduce(empty))
        expect_value_error(lambda: ops.all_reduce(ca._ptr, empty, empty, True, False, 0, 0))
        invalid = torch.empty(9, device='cuda', dtype=torch.float16)
        expect_value_error(lambda: ca.all_reduce(invalid))
        expect_value_error(lambda: ca.all_reduce(invalid[:8], out=invalid))
        # Fixed rank order matters when an FP32 accumulation loses a small
        # addend before a large cancellation. Check every rank bit-for-bit.
        for dtype in (torch.float16, torch.bfloat16, torch.float32):
            large, small = (2.**15, 2.**-9) if dtype == torch.float16 else (2.**80, 1.)
            for nbytes in (4096, 61440):
                inp = torch.empty(nbytes // torch.empty((), dtype=dtype).element_size(),
                                  device='cuda', dtype=dtype)
                def fill_ordered(scale):
                    values = [large, small, -large, small]
                    inp.fill_(values[rank % 4] * scale)
                    expected = torch.full_like(inp, values[0] * scale, dtype=torch.float32)
                    for r in range(1, world):
                        expected.add_(values[r % 4] * scale)
                    return expected.to(dtype)
                expected = fill_ordered(1.)
                torch.testing.assert_close(ca.custom_all_reduce(inp), expected, rtol=0, atol=0)
                graph = torch.cuda.CUDAGraph()
                with ca.capture(), torch.cuda.graph(graph):
                    out = ca.custom_all_reduce(inp)
                for repeat in range(8):
                    expected = fill_ordered(1. if repeat % 2 else -1.)
                    graph.replay()
                    torch.testing.assert_close(out, expected, rtol=0, atol=0)
                del graph, out, inp
        print('AR_ORDERED_SUM_PASS', rank, world, requested, flush=True)
        # Local-input LL must keep the staging fallback for sliced or aliased
        # buffers. Refresh the same allocation before every graph replay.
        for dtype in (torch.float16, torch.bfloat16):
            for nbytes in (4096, 65536):
                n = nbytes // 2
                for layout in ('aligned', 'unaligned_input', 'same_output', 'overlap_output'):
                    storage = torch.empty(n + 8, device='cuda', dtype=dtype)
                    inp = storage[1:n+1] if layout == 'unaligned_input' else storage[:n]
                    out = (inp if layout == 'same_output' else storage[8:n+8]
                           if layout == 'overlap_output' else torch.empty_like(inp))
                    inp.fill_(rank / 8.)
                    ca.all_reduce(inp, out=out)
                    torch.testing.assert_close(out, torch.full_like(out, world*(world-1)/16),
                                               rtol=0, atol=0)
                    graph = torch.cuda.CUDAGraph()
                    with ca.capture(), torch.cuda.graph(graph):
                        ca.all_reduce(inp, out=out)
                    for repeat in range(8):
                        inp.fill_(rank / 8. + repeat / 8.)
                        graph.replay()
                        torch.testing.assert_close(out, torch.full_like(out,
                            world*(world-1)/16 + world*repeat/8), rtol=0, atol=0)
                    del graph, inp, out, storage
        print('AR_LOCAL_INPUT_LAYOUT_PASS', rank, world, requested, flush=True)
        sizes = (16, 4096, 32752, 32768, 32784, 57328, 57344, 57360, 65520, 65536, 65552,
                 262128, 262144, 262160, 917488, 917504, 917520, (2 << 20)+64, (2 << 20)+128)
        failures = 0
        for dtype in (torch.float16, torch.bfloat16, torch.float32):
            elem = torch.empty((), dtype=dtype).element_size()
            nmax = max(sizes)//elem
            for cycle in range(2):
                inp = torch.empty(nmax, device='cuda', dtype=dtype)
                base = (torch.arange(nmax, device='cuda') % 8).to(dtype)/8
                seed = base + rank
                graphs, outputs, orders = [], [], [sizes, tuple(reversed(sizes))]

                def chain(order):
                    inp.copy_(seed)
                    result = []
                    for nbytes in order:
                        out = ca.custom_all_reduce(inp[:nbytes//elem])
                        assert out is not None
                        result.append(out)
                        inp.add_(.125)
                    return result

                chain(sizes)
                torch.cuda.synchronize()
                dist.barrier()
                for order in orders:
                    graph = torch.cuda.CUDAGraph()
                    with ca.capture(), torch.cuda.graph(graph):
                        result = chain(order)
                    graphs.append(graph)
                    outputs.append(result)
                for replay in range(args.repeats):
                    which, shift = replay % 2, replay % 4
                    seed.copy_(base + rank + shift)
                    torch.cuda.synchronize()
                    dist.barrier()
                    if rank == replay % world:
                        time.sleep(.002)
                    graphs[which].replay()
                    torch.cuda.synchronize()
                    for step, (nbytes, out) in enumerate(zip(orders[which], outputs[which])):
                        expected = ((base[:nbytes//elem].float()+shift+step*.125)*world
                                    + world*(world-1)/2).to(dtype)
                        count = int(torch.count_nonzero(out != expected))
                        if count:
                            failures += 1
                            print('AR_BOUNDARY_FAIL', json.dumps(dict(rank=rank,dtype=str(dtype),
                                  cycle=cycle,replay=replay,nbytes=nbytes,mismatches=count,
                                  max_error=float((out.float()-expected.float()).abs().max()))),flush=True)
                print('AR_BOUNDARY_RESULT', json.dumps(dict(rank=rank,world=world,dtype=str(dtype),
                      cycle=cycle,graphs=2,replays=args.repeats,cases_per_graph=len(sizes),
                      input_ptr=inp.data_ptr(),failures=failures)),flush=True)
                del graphs, outputs, graph, result, inp, seed, base
                torch.cuda.synchronize()
                dist.barrier()
        counts = [None]*world
        dist.all_gather_object(counts, failures)
        assert not any(counts), f'AR mixed graph failures: {counts}'
        if requested != 'off':
            ca.close()
            ca = CustomAllreduce(dist.group.WORLD, local, max_size=64 << 10,
                                 enable_register_for_capturing=True)
            assert not ca.disabled and ca.small_ar_mode == 'off'
            tiny = torch.full((8,), rank+1, device='cuda', dtype=torch.float16)
            result = ca.custom_all_reduce(tiny)
            torch.testing.assert_close(result, torch.full_like(tiny,world*(world+1)/2),rtol=0,atol=0)
            # Public admission keeps the historical half-capacity bound;
            # explicit all_reduce may fill the entire staging allocation.
            edge = torch.full((ca.max_size // 4,), rank+1, device='cuda', dtype=torch.float16)
            assert ca.should_custom_ar(edge)
            torch.testing.assert_close(ca.custom_all_reduce(edge),
                                       torch.full_like(edge,world*(world+1)/2),rtol=0,atol=0)
            full = torch.full((ca.max_size // 2,), rank+1, device='cuda', dtype=torch.float16)
            assert ca.custom_all_reduce(full) is None
            torch.testing.assert_close(ca.all_reduce(full),
                                       torch.full_like(full,world*(world+1)/2),rtol=0,atol=0)
            oversized = torch.empty(ca.max_size // 2 + 8, device='cuda', dtype=torch.float16)
            try:
                ca.all_reduce(oversized)
            except RuntimeError as exc:
                assert 'registered buffer is too small' in str(exc)
            else:
                raise AssertionError('staging capacity overflow was accepted')
            print('AR_INPUT_CAPACITY_BOUNDARY_PASS',rank,flush=True)
            expect_value_error(lambda: ops.configure_small_ar(ca._ptr, 64 << 20,
                               ca._pool['meta'].max_size, 3))
            print('AR_SMALL_CAPACITY_FALLBACK_PASS',rank,flush=True)
            ca.close()
            ca = None
            # Simulate one unsupported participant in the capability exchange;
            # all ranks must fall back before allocating or launching LL.
            gather = dist.all_gather_object
            def one_unsupported(outputs, value, *args, **kwargs):
                if isinstance(value, tuple) and len(value) == 3 and value[0] == requested:
                    value = (value[0], value[1], value[2] and rank != 0)
                return gather(outputs, value, *args, **kwargs)
            with patch.object(dist, 'all_gather_object', side_effect=one_unsupported):
                ca = CustomAllreduce(dist.group.WORLD, local, max_size=64 << 20)
            assert not ca.disabled and ca.small_ar_mode == 'off'
            torch.testing.assert_close(ca.custom_all_reduce(tiny),
                                       torch.full_like(tiny,world*(world+1)/2),rtol=0,atol=0)
            print('AR_SIMULATED_CAPABILITY_FALLBACK_PASS',rank,flush=True)
            ca.close()
            ca = None
            with patch.dict(os.environ, {'AITER_AR_SMALL_MESSAGE': 'll' if rank == 0 else 'll128'}):
                expect_value_error(lambda: CustomAllreduce(dist.group.WORLD, local, max_size=64 << 20))
            print('AR_CONFIG_MISMATCH_REJECT_PASS',rank,flush=True)
    finally:
        if ca is not None:
            ca.close()
        dist.destroy_process_group()


def run_ar_precision(args):
    """Exact ordered sums, rounding ties and guarded partial partitions."""
    import hashlib
    local = int(os.environ['LOCAL_RANK'])
    torch.cuda.set_device(local)
    dist.init_process_group('gloo', timeout=timedelta(seconds=180))
    rank, world = dist.get_rank(), dist.get_world_size()
    ca = None
    try:
        ca = CustomAllreduce(dist.group.WORLD, local, max_size=80 << 20,
                             enable_register_for_capturing=True)
        assert not ca.disabled and ca.transport == 'ipc'
        assert os.environ.get('AITER_AR_SMALL_MESSAGE', 'off') in ('off', 'auto')
        sizes = (16, 4096, 32752, 32768, 32784, 65536, 81920, 163840, 196608,
                 (1 << 20)-16, 1 << 20, (1 << 20)+16,
                 2 << 20, (2 << 20)+16, (2 << 20)+32, (2 << 20)+48,
                 (2 << 20)+64, (2 << 20)+128, 8 << 20, 32 << 20)
        for dtype in (torch.float16, torch.bfloat16, torch.float32):
            elem = torch.empty((), dtype=dtype).element_size()
            ulp = {torch.float16: 2.**-10, torch.bfloat16: 2.**-7,
                   torch.float32: 2.**-23}[dtype]
            large = 2.**15 if dtype == torch.float16 else 2.**80
            cancel = (large, 1., -large, 1.)
            values = []
            for r in range(world):
                values.append(torch.tensor([
                    1. if r == 0 else ulp/2 if r == 1 else 0.,
                    1.+ulp if r == 0 else ulp/2 if r == 1 else 0.,
                    -1. if r == 0 else -ulp/2 if r == 1 else 0.,
                    -1.-ulp if r == 0 else -ulp/2 if r == 1 else 0.,
                    cancel[r % 4], -cancel[r % 4],
                    torch.finfo(dtype).tiny / 2, (r+1)/8.,
                    -0., 0., -(r+1)/8., torch.finfo(dtype).max,
                    ulp/2, -ulp/2, torch.finfo(dtype).tiny,
                    float('inf') if r == 0 else float('-inf') if r == 1 else 0.,
                ], dtype=dtype))
            own = values[rank].cuda()
            for nbytes in sizes:
                n = nbytes // elem
                pattern = torch.arange(n, device='cuda') % 16
                inp = own[pattern]
                storage = torch.full((n + 32,), 17., device='cuda', dtype=dtype)
                out = storage[16:n+16]
                two_stage = world > 2 and nbytes >= (160 << 10 if world <= 4 else 80 << 10)
                pack = 16 // elem
                part = (nbytes // 16) // world

                def flush_fp32(value):
                    # AITER JIT already builds HIP with
                    # -fgpu-flush-denormals-to-zero. Model that existing FP32
                    # arithmetic mode explicitly; do not use a tolerance.
                    return torch.where(value.abs() < torch.finfo(torch.float32).tiny,
                                       torch.copysign(torch.zeros_like(value), value), value)

                def expected(sign):
                    result = torch.empty_like(inp)
                    for owner in range(world if two_stage else 1):
                        order = [(owner+r) % world for r in range(world)] if two_stage else list(range(world))
                        ref = flush_fp32(values[order[0]].float() * sign)
                        for r in order[1:]:
                            ref = flush_fp32(ref + flush_fp32(values[r].float() * sign))
                        begin = owner * part * pack if two_stage else 0
                        end = ((owner+1)*part*pack if owner < world-1 else n) if two_stage else n
                        result[begin:end] = ref.to(dtype).cuda()[pattern[begin:end]]
                    return result

                digest = hashlib.sha256()
                graph = torch.cuda.CUDAGraph()
                ca.all_reduce(inp, out=out)
                torch.testing.assert_close(out, expected(1.), rtol=0, atol=0, equal_nan=True)
                assert torch.all(storage[:16] == 17.) and torch.all(storage[n+16:] == 17.)
                with ca.capture(), torch.cuda.graph(graph):
                    ca.all_reduce(inp, out=out)
                for replay in range(8):
                    sign = 1. if replay % 2 else -1.
                    inp.copy_(own[pattern] * sign)
                    graph.replay()
                    torch.testing.assert_close(out, expected(sign), rtol=0, atol=0, equal_nan=True)
                    assert torch.all(storage[:16] == 17.) and torch.all(storage[n+16:] == 17.)
                    # Normalize NaN payloads for a stable cross-build digest.
                    bits = torch.where(torch.isnan(out), torch.zeros_like(out), out).view(torch.uint8).cpu()
                    digest.update(bits.numpy().tobytes())
                    digest.update(torch.isnan(out).to(torch.uint8).cpu().numpy().tobytes())
                print('AR_PRECISION_RESULT', json.dumps(dict(rank=rank, world=world,
                      dtype=str(dtype), nbytes=nbytes, replays=8, exact=True,
                      guarded=True, reference='ordered_fp32_ftz_rne', sha256=digest.hexdigest())), flush=True)
                del graph, inp, out, storage, pattern
                torch.cuda.synchronize()
                dist.barrier()
    finally:
        if ca is not None:
            ca.close()
        dist.destroy_process_group()


SUITES = ('reuse', 'ar-boundaries', 'ar-precision', 'collectives', 'fusions', 'transport')
AR_SUITES = frozenset(SUITES[:3])


def make_plan(args):
    suites = SUITES if args.suite == 'all' else (args.suite,)
    plan = []
    for suite in suites:
        mode = args.small_message
        if mode is None:
            mode = ('both' if suite in AR_SUITES else 'off') if args.suite == 'all' else os.environ.get('AITER_AR_SMALL_MESSAGE', 'off')
        if mode not in ('off', 'auto', 'll', 'll128', 'both'):
            raise ValueError(f'unsupported AITER_AR_SMALL_MESSAGE={mode!r}')
        for selected in (('off', 'auto') if mode == 'both' else (mode,)):
            plan.append((suite, selected))
    return plan


def worker_command(args, tp, suite, mode):
    command = [sys.executable, '-m', 'torch.distributed.run', '--standalone',
               '--nnodes=1', f'--nproc-per-node={tp}', '--max-restarts=0',
               str(Path(__file__).resolve()), '--suite', suite,
               '--small-message', mode, '--repeats', str(args.repeats),
               '--close-repeats', str(args.close_repeats),
               '--transport', args.transport, '--register', args.register]
    if args.tp6:
        command.append('--tp6')
    if args.fabric_disabled:
        command.append('--fabric-disabled')
    return command


def run_job(command, env, log_path, timeout):
    with log_path.open('w', encoding='utf-8') as log:
        process = subprocess.Popen(command, env=env, stdout=log, stderr=subprocess.STDOUT,
                                   start_new_session=(os.name == 'posix'))
        try:
            return process.wait(timeout=timeout), False
        except subprocess.TimeoutExpired:
            # Kill this launcher's whole process group, including its ranks.
            if os.name == 'posix':
                os.killpg(process.pid, signal.SIGTERM)
            else:
                process.terminate()
            try:
                process.wait(timeout=10)
            except subprocess.TimeoutExpired:
                if os.name == 'posix':
                    os.killpg(process.pid, signal.SIGKILL)
                else:
                    process.kill()
                process.wait()
            return 124, True


def launch_ci(args, parser):
    try:
        allocation = int(os.environ.get('AITER_AR_TP_SIZE', '4'))
        if allocation not in (2, 4, 8):
            raise ValueError('AITER_AR_TP_SIZE must be 2, 4 or 8')
        tp_sizes = ([6] if args.tp6 else [args.tp_size] if args.tp_size else
                    [tp for tp in (2, 4) if tp <= allocation])
        plan = make_plan(args)
    except ValueError as exc:
        parser.error(str(exc))
    jobs = [(tp, suite, mode, worker_command(args, tp, suite, mode))
            for tp in tp_sizes for suite, mode in plan]
    if args.dry_run:
        print(json.dumps(dict(tp_sizes=tp_sizes, jobs=[dict(tp=tp, suite=s, small_message=m, command=c)
              for tp, s, m, c in jobs]), indent=2))
        return
    import torch
    available = torch.cuda.device_count()
    if available < max(tp_sizes):
        parser.error(f'TP{max(tp_sizes)} requires {max(tp_sizes)} visible GPUs, found {available}; '
                     'select GPUs with HIP_VISIBLE_DEVICES or request --tp-size 2')
    root = Path(args.output).resolve()
    root.mkdir(parents=True, exist_ok=True)
    run_dir = Path(tempfile.mkdtemp(prefix='run-', dir=root))
    report = dict(tp_sizes=tp_sizes, status='running', planned_jobs=len(jobs), jobs=[])
    report_path = run_dir / 'summary.json'

    def save_report():
        report_path.write_text(json.dumps(report, indent=2) + '\n', encoding='utf-8')

    save_report()
    print(f'CAR_CI_START TP={tp_sizes} jobs={len(jobs)} report={report_path}', flush=True)
    for tp, suite, mode, command in jobs:
        log_path = run_dir / f'tp{tp}_{suite}_{mode}.log'
        rank_dir = run_dir / f'tp{tp}_{suite}_{mode}'
        rank_dir.mkdir()
        env = dict(os.environ, AITER_AR_SMALL_MESSAGE=mode, PYTHONUNBUFFERED='1',
                   AITER_CAR_CI_REPORT_DIR=str(rank_dir))
        print(f'CAR_CI_JOB_START tp={tp} suite={suite} mode={mode}', flush=True)
        started = time.monotonic()
        rc, timed_out = run_job(command, env, log_path, args.timeout)
        # Separate rank files avoid interleaved stdout corrupting verdicts.
        # Every rank must finish; exit 0 alone is insufficient.
        records = [json.loads(path.read_text(encoding='utf-8'))
                   for path in sorted(rank_dir.glob('rank*.json'))]
        ranks = [record['rank'] for record in records]
        passed = (rc == 0 and sorted(ranks) == list(range(tp)) and
                  all(r['world'] == tp and r['suite'] == suite and r['small_message'] == mode
                      for r in records))
        report['jobs'].append(dict(tp=tp, suite=suite, small_message=mode, status='passed' if passed else 'failed',
            returncode=rc, timed_out=timed_out, elapsed_s=time.monotonic()-started,
            command=command, log=str(log_path), workers=records))
        report['status'] = 'running' if passed else 'failed'
        save_report()
        print(f'CAR_CI_JOB_{"PASS" if passed else "FAIL"} tp={tp} suite={suite} mode={mode} log={log_path}', flush=True)
        if not passed:
            print(log_path.read_text(encoding='utf-8', errors='replace'), flush=True)
            raise SystemExit(rc if rc > 0 else 1)
    report['status'] = 'passed'
    save_report()
    print(f'CAR_CI_PASS jobs={len(jobs)} report={report_path}', flush=True)


def worker_provenance(args):
    libraries = {}
    maps = Path('/proc/self/maps')
    if maps.exists():
        for line in maps.read_text().splitlines():
            name = line.split()[-1]
            if 'module_custom_all_reduce' in name and name.endswith('.so') and name not in libraries:
                libraries[name] = hashlib.sha256(Path(name).read_bytes()).hexdigest()
        assert libraries, 'custom allreduce native library was not loaded'
    return dict(rank=int(os.environ['RANK']), world=int(os.environ['WORLD_SIZE']),
                suite=args.suite, small_message=os.environ['AITER_AR_SMALL_MESSAGE'],
                arch=torch.cuda.get_device_properties(int(os.environ['LOCAL_RANK'])).gcnArchName,
                python=str(Path(car.__file__).resolve()), native=libraries)


def main():
    parser = argparse.ArgumentParser(description=__doc__)
    parser.add_argument('--suite', default='all', choices=['all', *SUITES])
    parser.add_argument('--repeats', type=int, default=100)
    parser.add_argument('--close-repeats', type=int, default=20)
    parser.add_argument('--transport', choices=['ipc', 'fabric'], default='ipc')
    parser.add_argument('--register', choices=['off', 'on', 'both'], default='both')
    parser.add_argument('--tp6', action='store_true')
    parser.add_argument('--tp-size', type=int, choices=[2, 4, 8],
                        help='run one TP size; default runs TP2 + TP4, limited by AITER_AR_TP_SIZE')
    parser.add_argument('--fabric-disabled', action='store_true')
    parser.add_argument('--small-message', choices=['off', 'auto', 'll', 'll128', 'both'],
                        help='all defaults to off/auto for AR suites and off for other suites; '
                             'a single suite otherwise inherits AITER_AR_SMALL_MESSAGE')
    parser.add_argument('--timeout', type=int, default=1800, help='timeout per independent torchrun job, seconds')
    parser.add_argument('--output', default='test_custom_allreduce_api_results', help='parent directory for unique run logs and summary.json')
    parser.add_argument('--dry-run', action='store_true', help='print the launch matrix without importing torch or using GPUs')
    args = parser.parse_args()
    if args.repeats < 2 or args.close_repeats < 1:
        parser.error('repeats must be >= 2 and close-repeats >= 1')
    if (args.tp6 or args.fabric_disabled) and args.suite != 'transport':
        parser.error('--tp6 and --fabric-disabled require --suite transport')
    if args.tp6 and args.tp_size:
        parser.error('--tp6 and --tp-size are mutually exclusive')
    if args.timeout < 1:
        parser.error('--timeout must be positive')
    if args.transport == 'fabric' and args.suite != 'collectives':
        parser.error('--transport fabric requires --suite collectives')
    distributed = any(k in os.environ for k in ('RANK', 'LOCAL_RANK', 'WORLD_SIZE'))
    if not distributed:
        return launch_ci(args, parser)
    if not all(k in os.environ for k in ('RANK', 'LOCAL_RANK', 'WORLD_SIZE')):
        parser.error('incomplete torchrun environment: RANK, LOCAL_RANK and WORLD_SIZE are required')
    if args.suite == 'all' or args.small_message == 'both' or args.dry_run:
        parser.error('use plain python for the multi-suite/dry-run launcher; torchrun requires one --suite and one mode')
    world = int(os.environ['WORLD_SIZE'])
    if args.tp_size and args.tp_size != world:
        parser.error('--tp-size must match WORLD_SIZE under torchrun')
    if world not in ((6,) if args.tp6 else (2, 4, 8)):
        parser.error('this suite requires TP2/4/8; --tp6 is only for transport')
    mode = args.small_message or os.environ.get('AITER_AR_SMALL_MESSAGE', 'off')
    if mode not in ('off', 'auto', 'll', 'll128'):
        parser.error(f'unsupported AITER_AR_SMALL_MESSAGE={mode!r}')
    os.environ['AITER_AR_SMALL_MESSAGE'] = mode
    load_worker_runtime()
    if args.suite == 'collectives':
        os.environ['AITER_AR_TRANSPORT'] = args.transport
        run_collectives(args)
    elif args.suite == 'fusions':
        run_fusions(args)
    elif args.suite == 'reuse':
        run_reuse(args)
    elif args.suite == 'ar-precision':
        run_ar_precision(args)
    elif args.suite == 'ar-boundaries':
        run_ar_boundaries(args)
    else:
        run_transport(args)
    record = worker_provenance(args)
    if os.environ.get('AITER_CAR_CI_REPORT_DIR'):
        path = Path(os.environ['AITER_CAR_CI_REPORT_DIR']) / f'rank{record["rank"]}.json'
        temporary = path.with_suffix('.tmp')
        temporary.write_text(json.dumps(record) + '\n', encoding='utf-8')
        temporary.replace(path)
    print('CAR_CI_WORKER_PASS ' + json.dumps(record), flush=True)


if __name__ == '__main__':
    main()
