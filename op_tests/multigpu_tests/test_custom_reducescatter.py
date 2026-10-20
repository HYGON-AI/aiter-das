# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.

"""8-bit native ReduceScatter: CPU numeric oracle, changing-input Graph, RCCL.

Run via torchrun. RCCL is initialized by --bench or --check-fallback.
INT8 uses INT32/modulo-256; FP8 uses ordered FP32 SUM then non-saturating RNE.
"""
import argparse
from datetime import timedelta
import hashlib
import json
import math
import os
from pathlib import Path
import statistics
import time
from types import SimpleNamespace


def pattern(shape, dtype, rank, iteration=0, pairs=False):
    index = torch.arange(math.prod(shape), dtype=torch.int64)
    if pairs:
        codes = index // 256 if rank == 0 else index % 256 if rank == 1 else torch.zeros_like(index)
    else:
        codes = (index * (2 * iteration + 1) + rank * 37 + iteration * 19) % 256
    return codes.to(torch.uint8).reshape(shape).view(dtype)


def reference(shape, dtype, rank, world, dim, iteration=0, pairs=False):
    acc = torch.zeros(shape, dtype=torch.int32 if dtype == torch.int8 else torch.float32)
    for source in range(world):
        value = pattern(shape, dtype, source, iteration, pairs)
        acc.add_(value.to(acc.dtype) if dtype == torch.int8 else fp8_table(dtype)[0][value.view(torch.uint8).long()])
    shard = acc.chunk(world, dim=dim)[rank].contiguous()
    return int8_wrap(shard) if dtype == torch.int8 else fp8_encode_oracle(shard, dtype)


def exact(actual, expected):
    actual = actual.cpu()
    assert actual.shape == expected.shape and actual.dtype == expected.dtype
    if actual.dtype == torch.int8:
        mask = torch.ones_like(actual, dtype=torch.bool)
    else:
        nan_a, nan_b = actual.float().isnan(), expected.float().isnan()
        bad_nan = nan_a != nan_b
        assert not bad_nan.any(), (f'NaN classification mismatch count={bad_nan.sum().item()} '
                                   f'actual={actual.view(torch.uint8)[bad_nan][:16]} '
                                   f'expected={expected.view(torch.uint8)[bad_nan][:16]}')
        mask = ~nan_a
    a, b = actual.view(torch.uint8), expected.view(torch.uint8)
    if actual.element_size() > 1:
        mask = mask.repeat_interleave(actual.element_size(), dim=-1)
    bad = mask & (a != b)
    assert not bad.any(), f'byte mismatches={bad.sum().item()} actual={a[bad][:16]} expected={b[bad][:16]}'


def expect_error(fn, expected=(ValueError, RuntimeError, AssertionError), message=None):
    try:
        fn()
    except expected as exc:
        if message is not None:
            assert message in str(exc), str(exc)
        return
    raise AssertionError('expected validation failure')


def correctness(ca, args, rank, world, device):
    from aiter.ops import custom_all_reduce as ops
    from aiter.dist.device_communicators.communicator_cuda import CudaCommunicator
    public = object.__new__(CudaCommunicator)
    public.ca_comm, public.world_size = ca, world
    cases = 0
    shapes = [((world * 16,), 0), ((world * 4, 64), 0),
              ((16, world * 32), -1), ((16, world * 3), -1),
              ((2, world * 3, 32), 1), ((16, world * 3, 3), 1),
              ((2, 2, world * 3, 16), -2),
              ((16, 512), 0), ((16, 512), -1)]
    for dtype in [torch.int8, *FP8_DTYPES, torch.float16, torch.bfloat16, torch.float32]:
        for shape, dim in shapes:
            # Legacy floats use finite integer values for exact reduction.
            byte_dtype = dtype == torch.int8 or dtype in FP8_DTYPES
            def value(source, iteration):
                if byte_dtype:
                    return pattern(shape, dtype, source, iteration)
                return torch.full(shape, float(source + iteration), dtype=dtype)
            def wanted(iteration):
                if byte_dtype:
                    return reference(shape, dtype, rank, world, dim, iteration)
                return sum(value(r, iteration).float() for r in range(world)).chunk(world, dim)[rank].contiguous().to(dtype)
            inp = value(rank, 0).to(device)
            out = torch.empty_like(wanted(0), device=device)
            assert ca.should_custom_rs(inp, dim), (dtype, shape, dim)
            ca.reduce_scatter(inp, out, dim)
            exact(out, wanted(0))
            ca.reduce_scatter(inp, out, dim, registered=True)
            exact(out, wanted(0))
            ca.custom_reduce_scatter(inp, out, dim)
            exact(out, wanted(0))
            exact(public.reduce_scatter(inp, dim), wanted(0))
            with ca.capture():
                ca.custom_reduce_scatter(inp, out, dim)  # warmup must produce data
                exact(out, wanted(0))
                graph = torch.cuda.CUDAGraph()
                with torch.cuda.graph(graph):
                    ca.custom_reduce_scatter(inp, out, dim)
                    inp.view(torch.uint8).fill_(0xA5)  # immediate producer reuse
            for iteration in range(args.repeats):
                inp.view(torch.uint8).copy_(value(rank, iteration).view(torch.uint8))
                if rank == 0 and iteration % 5 == 0:
                    time.sleep(.001)
                graph.replay()
                try:
                    exact(out, wanted(iteration))
                except AssertionError as exc:
                    raise AssertionError(f'dtype={dtype} shape={shape} dim={dim} rank={rank} replay={iteration}: {exc}') from exc
            del graph
            cases += 1
        if dtype == torch.int8 or dtype in FP8_DTYPES:
            # Exhaust every pair of 8-bit encodings, including special values,
            # cancellation, overflow, subnormals and halfway rounding cases.
            shape = (65536,)
            inp = pattern(shape, dtype, rank, pairs=True).to(device)
            want = reference(shape, dtype, rank, world, 0, pairs=True)
            out = torch.empty_like(want, device=device)
            ca.reduce_scatter(inp, out)
            exact(out, want)
            if dtype in (torch.int8, torch.float8_e4m3fn):
                ops.reduce_scatter(ca._ptr, inp, out, ca._pool['input'].data_ptr, ca._pool['input'].max_size)
                exact(out, want)
                ops.reduce_scatter_dim(ca._ptr, inp, out, 0, 0, inp.numel(), 0,
                                       ca._pool['input'].data_ptr, ca._pool['input'].max_size)
                exact(out, want)
            # Copy-in accepts unaligned input; output alignment is checked.
            backing = torch.empty(inp.numel() + 1, dtype=torch.uint8, device=device)
            offset = backing[1:].view(dtype)
            offset.view(torch.uint8).copy_(inp.view(torch.uint8))
            ca.reduce_scatter(offset, out)
            exact(out, want)
            bad = torch.empty(out.numel() + 1, dtype=torch.uint8, device=device)[1:].view(dtype)
            expect_error(lambda: ca.reduce_scatter(inp, bad))
            expect_error(lambda: ca.reduce_scatter(inp, inp[:out.numel()]))
            expect_error(lambda: ca.reduce_scatter(inp, out, dim=2))
            cases += 2
        if rank == 0:
            print('RS_DTYPE_PASS', str(dtype), flush=True)
        # All dtypes share the explicit output alignment contract, including
        # legacy floats and shapes that would otherwise use scalar kernels.
        for shape, dim in (((world * 16, 16), 0), ((16, world * 3), -1)):
            inp = torch.empty(shape, dtype=dtype, device=device)
            outshape = list(shape)
            outshape[dim] //= world
            backing = torch.empty(math.prod(outshape) + 1, dtype=dtype, device=device)
            bad = backing[1:].reshape(outshape)
            bad.view(torch.uint8).fill_(0xA5)
            assert bad.data_ptr() % 16
            expect_error(lambda: ca.reduce_scatter(inp, bad, dim))
            expect_error(lambda: ca.custom_reduce_scatter(inp, bad, dim))
            assert (bad.view(torch.uint8) == 0xA5).all().item()
            cases += 1
    # The legacy ABI's fp8 enum denotes E4M3FN only. E5M2 must carry format=3
    # through the byte-view entry; direct tensors must fail before launch.
    inp = torch.empty(world * 16, dtype=torch.float8_e5m2, device=device)
    out = torch.empty(16, dtype=inp.dtype, device=device)
    out.view(torch.uint8).fill_(0xA5)
    reg, capacity = ca._pool['input'].data_ptr, ca._pool['input'].max_size
    expect_error(lambda: ops.reduce_scatter(ca._ptr, inp, out, reg, capacity))
    expect_error(lambda: ops.reduce_scatter_dim(ca._ptr, inp, out, 0, 0, inp.numel(), 0, reg, capacity))
    assert (out.view(torch.uint8) == 0xA5).all().item()
    cases += 2
    for dtype in (torch.uint8, torch.int16, torch.int32, torch.int64):
        inp = torch.zeros(world * 16, dtype=dtype, device=device)
        out = torch.full((16,), 11, dtype=dtype, device=device)
        assert not ca.should_custom_rs(inp)
        assert ca.custom_reduce_scatter(inp, out) is None
        assert (out == 11).all().item()
        expect_error(lambda: ca.reduce_scatter(inp, out))
    # Reject dimensions beyond the shared Tensor ABI before native dispatch.
    for dtype in (torch.int8, *FP8_DTYPES, torch.float16, torch.bfloat16, torch.float32):
        shape = (world * 16,) + (1,) * 7 + (world,)
        inp = torch.zeros(shape, dtype=torch.uint8, device=device).to(dtype)
        for dim in (0, -1):
            output_shape = list(shape)
            output_shape[dim] //= world
            out = torch.empty(output_shape, dtype=dtype, device=device)
            out.view(torch.uint8).fill_(0xA5)
            assert not ca.should_custom_rs(inp, dim)
            assert ca.custom_reduce_scatter(inp, out, dim) is None
            expect_error(lambda: ca.reduce_scatter(inp, out, dim))
            assert (out.view(torch.uint8) == 0xA5).all().item()
            cases += 1
    inp = torch.zeros((16, world * 3), dtype=torch.int8, device=device)
    assert not ca.should_custom_rs(inp.t(), 0)
    assert not ca.should_custom_rs(inp.cpu(), 1)
    assert not ca.should_custom_rs(inp[:, :0], 1)
    assert not ca.should_custom_rs(torch.zeros(17, dtype=torch.int8, device=device), 0)
    old = ca.max_size
    ca.max_size = 16
    assert not ca.should_custom_rs(inp, 1)
    ca.max_size = old
    return cases + 4


def fallback_correctness(ca, args, rank, world, device):
    from aiter.dist.device_communicators.communicator_cuda import CudaCommunicator
    from aiter.dist.device_communicators.communicator_pynccl import PyNcclCommunicator
    public = object.__new__(CudaCommunicator)
    public.world_size, public.ca_comm = world, ca
    rccl = PyNcclCommunicator(dist.group.WORLD, device)
    assert not rccl.disabled
    public.pynccl_comm = rccl
    checks = 0
    for dtype in (*FP8_DTYPES, torch.float8_e4m3fnuz, torch.float8_e5m2fnuz):
        for reason in ('capacity', 'disabled', 'absent', 'alignment', 'ndim'):
            old_size, old_disabled = ca.max_size, ca.disabled
            shape = ((world * 3, 5) if reason == 'alignment' else
                     (world * 16,) + (1,) * 8 if reason == 'ndim' else (world * 16, 16))
            inp = torch.empty(shape, dtype=dtype, device=device)
            try:
                ca.max_size = 16 if reason == 'capacity' else old_size
                ca.disabled = reason == 'disabled'
                public.ca_comm = None if reason == 'absent' else ca
                expect_error(lambda: public.reduce_scatter(inp, 0), ValueError, 'FP8 reduce_scatter')
                checks += 1
            finally:
                ca.max_size, ca.disabled = old_size, old_disabled
                public.ca_comm = ca
    public.ca_comm = None
    for backend in (None, SimpleNamespace(disabled=True)):
        public.pynccl_comm = backend
        for dtype in (torch.int8, torch.float16, torch.bfloat16, torch.float32):
            inp = torch.empty(world * 16, dtype=dtype, device=device)
            expect_error(lambda: public.reduce_scatter(inp, 0), RuntimeError, 'active RCCL')
            checks += 1
    public.pynccl_comm = rccl
    # Force genuine RCCL fallback on nonaligned byte counts, middle/last dims,
    # and capacity refusal. Include positive/negative INT8 overflow.
    for dtype in (torch.int8, torch.float32):
        for shape, dim in (((world * 3, 5), 0), ((16, world * 3), -1),
                           ((16, world * 3, 3), 1)):
            def value(source, iteration):
                index = torch.arange(math.prod(shape)).reshape(shape)
                codes = ((index * 37 + source * 19 + iteration * 11) % 256).to(torch.uint8)
                return codes.view(torch.int8).to(dtype)
            def wanted(iteration):
                acc = sum(value(r, iteration).to(torch.int32 if dtype == torch.int8 else dtype)
                          for r in range(world)).chunk(world, dim)[rank].contiguous()
                return int8_wrap(acc) if dtype == torch.int8 else acc
            old_size = ca.max_size
            ca.max_size = 16
            public.ca_comm = ca
            try:
                inp = value(rank, 0).to(device)
                assert not ca.should_custom_rs(inp, dim)
                exact(public.reduce_scatter(inp, dim), wanted(0))
                graph = torch.cuda.CUDAGraph()
                with torch.cuda.graph(graph):
                    out = public.reduce_scatter(inp, dim)
                    inp.view(torch.uint8).fill_(0xA5)
                for iteration in range(args.repeats):
                    inp.copy_(value(rank, iteration))
                    graph.replay()
                    exact(out, wanted(iteration))
                del graph, out
                checks += 1
            finally:
                ca.max_size = old_size
    return checks


def summarize(values):
    return dict(samples_us=values, median_us=statistics.median(values),
                p95_us=sorted(values)[math.ceil(len(values) * .95) - 1],
                cv_pct=100 * statistics.pstdev(values) / statistics.mean(values))


def benchmark(ca, args, rank, world, device):
    from aiter.dist.device_communicators.communicator_pynccl import PyNcclCommunicator
    rccl = PyNcclCommunicator(dist.group.WORLD, device)
    assert not rccl.disabled
    rows = []
    for dtype in (torch.int8, torch.float8_e4m3fn):
        for size in map(int, args.sizes.split(',')):
            assert size > 0 and size % 256 == 0
            shape = (16, size // 16)
            inp = ((torch.arange(size) % 7) - 3).reshape(shape).to(dtype).to(device)
            for dim in (0, 1):
                assert ca.should_custom_rs(inp, dim)
                output_shape = list(shape)
                output_shape[dim] //= world
                out = torch.empty(output_shape, dtype=dtype, device=device)
                rccl_shape = (shape[dim] // world, shape[1 - dim])
                ref_dtype = torch.int8 if dtype == torch.int8 else torch.float32
                reduced = torch.empty(rccl_shape, dtype=ref_dtype, device=device)
                converted = torch.empty(shape, dtype=ref_dtype, device=device)
                ordered = torch.empty((shape[dim], shape[1 - dim]), dtype=ref_dtype, device=device)
                baseline_out = torch.empty_like(out)
                def custom():
                    ca.reduce_scatter(inp, out, dim)
                def baseline():
                    # FP8 RCCL reference includes cast/layout/FP32 communication
                    # and the final cast. It is NOT a native FP8 RCCL collective.
                    if dtype == torch.int8 and dim == 0:
                        rccl.reduce_scatter(baseline_out, inp)
                        return
                    if dtype == torch.int8:
                        ordered.copy_(inp.movedim(dim, 0))
                    else:
                        converted.copy_(inp)
                        if dim != 0:
                            ordered.copy_(converted.movedim(dim, 0))
                    rccl.reduce_scatter(reduced, converted if dtype != torch.int8 and dim == 0 else ordered)
                    baseline_out.copy_(reduced.movedim(0, dim))
                want = (inp.cpu().float() * world).chunk(world, dim)[rank].contiguous().to(dtype)
                custom(); baseline()
                exact(out, want); exact(baseline_out, want)
                for mode in ('eager', 'graph'):
                    functions = dict(custom=custom, rccl=baseline)
                    graphs = {}
                    if mode == 'graph':
                        for key, fn in functions.items():
                            for _ in range(3): fn()
                            torch.cuda.synchronize(); dist.barrier()
                            graph = torch.cuda.CUDAGraph()
                            with ca.capture(), torch.cuda.graph(graph):
                                for _ in range(args.iters): fn()
                            graphs[key] = graph
                        functions = {key:g.replay for key, g in graphs.items()}
                    samples = {key:[] for key in functions}
                    for repeat in range(args.rounds):
                        order = list(functions)
                        if repeat % 2: order.reverse()
                        for key in order:
                            fn = functions[key]
                            for _ in range(3): fn()
                            torch.cuda.synchronize(); dist.barrier()
                            start, end = torch.cuda.Event(enable_timing=True), torch.cuda.Event(enable_timing=True)
                            start.record()
                            for _ in range(1 if mode == 'graph' else args.iters): fn()
                            end.record(); end.synchronize()
                            elapsed = torch.tensor(start.elapsed_time(end) * 1000 / args.iters)
                            dist.all_reduce(elapsed, op=dist.ReduceOp.MAX)
                            samples[key].append(elapsed.item())
                    row = dict(dtype=str(dtype), bytes=size, dim=dim, mode=mode,
                               rccl_version=rccl.nccl_version,
                               rccl_payload_bytes=size * (1 if dtype == torch.int8 else 4),
                               baseline='RCCL_INT8_SUM' if dtype == torch.int8 else 'cast_FP32_RCCL_SUM_cast_FP8',
                               **{key:summarize(v) for key,v in samples.items()})
                    rows.append(row)
                    if rank == 0: print('RS_BENCH', json.dumps(row), flush=True)
                    del graphs, functions
    return rows


def main():
    parser = argparse.ArgumentParser(description=__doc__)
    parser.add_argument('--output', required=True)
    parser.add_argument('--repeats', type=int, default=20)
    parser.add_argument('--bench', action='store_true')
    parser.add_argument('--check-fallback', action='store_true',
                        help='also initialize RCCL and check public fallback contracts')
    parser.add_argument('--rounds', type=int, default=9)
    parser.add_argument('--iters', type=int, default=30)
    parser.add_argument('--sizes', default='256,4096,8192,32768,262144,1048576,4194304',
                        help='comma-separated input bytes per rank (INT8/FP8 benchmarks)')
    args = parser.parse_args()
    global torch, dist, FP8_DTYPES, fp8_table, fp8_encode_oracle, int8_wrap
    import torch
    import torch.distributed as dist
    from aiter.utility.dtypes import FP8_DTYPES
    from collective_reference import fp8_table, fp8_encode_oracle, int8_wrap
    from aiter.dist.device_communicators.custom_all_reduce import CustomAllreduce
    rank, local, world = (int(os.environ[k]) for k in ('RANK', 'LOCAL_RANK', 'WORLD_SIZE'))
    torch.cuda.set_device(local)
    device = torch.device('cuda', local)
    dist.init_process_group('gloo', timeout=timedelta(seconds=180))
    ca = CustomAllreduce(dist.group.WORLD, local, max_size=64 << 20, enable_register_for_capturing=True)
    assert not ca.disabled and ca.transport == 'ipc'
    report = dict(rank=rank, world=world, torch=torch.__version__, hip=torch.version.hip,
                  arch=torch.cuda.get_device_properties(local).gcnArchName,
                  effective_registered=ca.enable_register_for_capturing, arguments=vars(args))
    report['cases'] = correctness(ca, args, rank, world, device)
    report['fallback_checks'] = fallback_correctness(ca, args, rank, world, device) if args.check_fallback else 0
    report['benchmarks'] = benchmark(ca, args, rank, world, device) if args.bench else []
    torch.cuda.synchronize()
    report['native'] = {}
    for line in Path('/proc/self/maps').read_text().splitlines():
        path = line.split()[-1]
        if 'module_custom_all_reduce' in path and path.endswith('.so') and path not in report['native']:
            report['native'][path] = hashlib.sha256(Path(path).read_bytes()).hexdigest()
    assert report['native']
    report['status'] = 'passed'
    directory = Path(args.output)
    directory.mkdir(parents=True, exist_ok=True)
    (directory / f'rank{rank}.json').write_text(json.dumps(report, indent=2) + '\n')
    print('RS_PASS', json.dumps({k:v for k,v in report.items() if k != 'benchmarks'}), flush=True)
    dist.barrier()
    ca.close()
    dist.destroy_process_group()


if __name__ == '__main__':
    main()
