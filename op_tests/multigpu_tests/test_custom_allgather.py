# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.

"""Bit-exact custom AllGather validation and paired RCCL benchmarks.

Run under torchrun, e.g. --nproc_per_node=4 ... --mode correctness.
Benchmarks report same-payload custom/RCCL GPU-event times including copy-in.
FP8 references and RCCL transport use uint8, preserving every bit pattern.
"""
import argparse
from contextlib import nullcontext
from datetime import timedelta
import hashlib
import json
import math
import os
from pathlib import Path
import statistics
import time
from types import SimpleNamespace
import weakref


def arguments():
    p = argparse.ArgumentParser(description=__doc__)
    p.add_argument('--mode', choices=['correctness', 'bench', 'all'], default='correctness')
    p.add_argument('--output', required=True)
    p.add_argument('--repeats', type=int, default=20)
    p.add_argument('--rounds', type=int, default=7)
    p.add_argument('--iters', type=int, default=30)
    p.add_argument('--sizes', default='256,4096,8192,32768,262144,1048576,4194304',
                   help='comma-separated input bytes per rank')
    p.add_argument('--dtypes', default='int8,float8_e4m3fn')
    p.add_argument('--max-size-mib', type=int, default=64)
    return p.parse_args()


def byte_pattern(shape, dtype, rank, iteration=0):
    elem = torch.empty((), dtype=dtype).element_size()
    byte_shape = (*shape[:-1], shape[-1] * elem)
    return ((torch.arange(math.prod(byte_shape), dtype=torch.int64)
             + rank * 37 + iteration * 19) % 256).to(torch.uint8).reshape(byte_shape)


def reference(shape, dtype, world, dim, iteration=0):
    return torch.cat([byte_pattern(shape, dtype, r, iteration) for r in range(world)], dim=dim)


def exact(output, expected):
    assert output is not None, 'custom path unexpectedly declined the input'
    actual = output.view(torch.uint8).cpu()
    assert actual.shape == expected.shape
    assert torch.equal(actual, expected), f'byte mismatch count={(actual != expected).sum().item()}'


def expect_error(fn):
    try:
        fn()
    except ValueError:
        return
    raise AssertionError('expected validation error')


def correctness(ca, group, args, rank, world, device):
    dtypes = [torch.int8, torch.uint8, *FP8_DTYPES,
              torch.float16, torch.bfloat16, torch.float32,
              torch.int16, torch.int32, torch.int64]
    cases = 0
    for dtype in dtypes:
        for shape, dim in [((16,), 0), ((256,), 0), ((8, 32), 0), ((8, 32), -1),
                           ((2, 4, 32), -1), ((16, 3), 0),
                           ((8, 1024), 0), ((8, 1024), -1)]:
            inp = byte_pattern(shape, dtype, rank).to(device).view(dtype)
            assert ca.should_custom_ag(inp, dim), (dtype, shape, dim)
            want = reference(shape, dtype, world, dim)
            out = torch.empty(want.shape, dtype=torch.uint8, device=device).view(dtype)
            assert ca.all_gather_unreg(inp, out=out, dim=dim) is out
            exact(out, want)
            # This also exercises the native copy-in override on DTK.
            exact(ca.all_gather_reg(inp, dim=dim), want)
            exact(group.all_gather(inp, use_custom=True, dim=dim), want)
            # ProcessGroupNCCL does not accept int16; native AG still covers it.
            if dtype != torch.int16:
                exact(group.all_gather(inp, use_custom=False, dim=dim), want)
            with ca.capture():
                exact(ca.custom_all_gather(inp, dim), want)  # warmup must write
                graph = torch.cuda.CUDAGraph()
                with torch.cuda.graph(graph):
                    result = ca.custom_all_gather(inp, dim)
                    # A producer may reuse input immediately after the collective.
                    inp.view(torch.uint8).fill_(0xA5)
            for iteration in range(args.repeats):
                inp.view(torch.uint8).copy_(byte_pattern(shape, dtype, rank, iteration))
                if rank == 0 and iteration % 5 == 0:
                    time.sleep(.001)  # asymmetric rank arrival, outside timing
                graph.replay()
                exact(result, reference(shape, dtype, world, dim, iteration))
            del graph, result
            cases += 1
        # Contiguous but unaligned source is legal via copy-in; unaligned out is not.
        elem = torch.empty((), dtype=dtype).element_size()
        backing = torch.arange(272, dtype=torch.int64, device=device).to(torch.uint8)
        inp = backing[elem:elem + 256].view(dtype)
        exact(ca.custom_all_gather(inp), torch.cat([inp.view(torch.uint8).cpu()] * world))
        badout = torch.empty(256 * world + elem, dtype=torch.uint8, device=device)[elem:].view(dtype)
        expect_error(lambda: ca.all_gather_unreg(inp, out=badout))
        empty = torch.empty((0, 32), dtype=dtype, device=device)
        assert ca.custom_all_gather(empty) is None
        assert ca.custom_all_gather(inp, dim=3) is None
        expect_error(lambda: ca.all_gather_unreg(inp, dim=3))
        overlap = torch.empty(256 * world, dtype=torch.uint8, device=device).view(dtype)
        expect_error(lambda: ca.all_gather_unreg(overlap[:256 // inp.element_size()], out=overlap))
        if rank == 0:
            print('AG_DTYPE_PASS', str(dtype), flush=True)
    # FP8 fallback: nonaligned size, unsupported middle dimension, noncontiguous,
    # disabled custom communicator and capacity overflow. Check PyNccl and c10d.
    for dtype in [torch.int8, *FP8_DTYPES]:
        for shape, dim in [((17,), 0), ((3, 17), -1), ((2, 3, 16), 1)]:
            inp = byte_pattern(shape, dtype, rank).to(device).view(dtype)
            assert not ca.should_custom_ag(inp, dim)
            exact(group.all_gather(inp, use_custom=True, dim=dim), reference(shape, dtype, world, dim))
            exact(group.all_gather(inp, use_custom=False, dim=dim), reference(shape, dtype, world, dim))
            cases += 1
        inp = byte_pattern((8, 32), dtype, rank).to(device).view(dtype)
        old_size = ca.max_size
        ca.max_size = 16  # force capacity fallback without allocating large buffers
        try:
            exact(group.all_gather(inp, use_custom=True, dim=-1), reference((8, 32), dtype, world, -1))
        finally:
            ca.max_size = old_size
        ca.disabled = True
        try:
            exact(group.all_gather(inp, use_custom=True, dim=-1), reference((8, 32), dtype, world, -1))
            graph = torch.cuda.CUDAGraph()
            with torch.cuda.graph(graph):
                fallback_out = group.all_gather(inp, use_custom=True, dim=-1)
            for iteration in range(3):
                inp.view(torch.uint8).copy_(byte_pattern((8, 32), dtype, rank, iteration))
                graph.replay()
                exact(fallback_out, reference((8, 32), dtype, world, -1, iteration))
            del graph, fallback_out
        finally:
            ca.disabled = False
        # Same dtype views of transposed FP8 storage do not require FP8 arithmetic.
        inp = byte_pattern((8, 32), dtype, rank).to(device).view(dtype).t()
        wants = torch.cat([byte_pattern((8, 32), dtype, r).t() for r in range(world)], dim=-1)
        exact(group.all_gather(inp, use_custom=True, dim=-1), wants)
        cases += 4
    # Public Graph routes, both first/last dimension, with native calls enforced.
    for dtype in (torch.int8, *FP8_DTYPES):
        for dim in (0, -1):
            inp = byte_pattern((8, 32), dtype, rank).to(device).view(dtype)
            with ca.capture():
                group.all_gather(inp, use_custom=True, dim=dim)
                graph = torch.cuda.CUDAGraph()
                with torch.cuda.graph(graph):
                    result = group.all_gather(inp, use_custom=True, dim=dim)
            for iteration in range(args.repeats):
                inp.view(torch.uint8).copy_(byte_pattern((8, 32), dtype, rank, iteration))
                graph.replay()
                exact(result, reference((8, 32), dtype, world, dim, iteration))
            del graph, result
            cases += 1
    return cases


def summarize(samples):
    ordered = sorted(samples)
    mean = statistics.mean(samples)
    return dict(median_us=statistics.median(samples),
                p95_us=ordered[math.ceil(.95 * len(samples)) - 1],
                cv_pct=statistics.pstdev(samples) / mean * 100 if mean else 0,
                samples_us=samples)


def benchmark(ca, group, args, rank, world, device):
    rows = []
    for name in args.dtypes.split(','):
        dtype = getattr(torch, name)
        for nbytes in map(int, args.sizes.split(',')):
            assert nbytes % 256 == 0
            shape = (8, nbytes // (8 * torch.empty((), dtype=dtype).element_size()))
            inp = byte_pattern(shape, dtype, rank).to(device).view(dtype)
            for dim in (0, -1):
                assert ca.should_custom_ag(inp, dim), (shape, dim)
                want = reference(shape, dtype, world, dim)
                out = torch.empty(want.shape, dtype=torch.uint8, device=device).view(dtype)
                rccl_rank_major = torch.empty((world,) + shape, dtype=dtype, device=device)
                def custom():
                    return ca.all_gather_unreg(inp, out=out, dim=dim)
                def rccl():
                    group.device_communicator.pynccl_comm.all_gather(
                        rccl_rank_major.view(torch.uint8), inp.view(torch.uint8))
                    return rccl_rank_major.view(torch.uint8).movedim(0, dim % inp.ndim).reshape(want.shape).view(dtype)
                def api():
                    return group.all_gather(inp, use_custom=True, dim=dim)
                def legacy():
                    # Prior public layout strategy, same byte transport/copy-in.
                    x = ca.custom_all_gather(inp, dim=0).view(torch.uint8)
                    return x.reshape((world,) + tuple(inp.view(torch.uint8).shape)).movedim(
                        0, dim % inp.ndim).reshape(want.shape).view(dtype)
                functions = dict(custom=custom, rccl=rccl, api=api, legacy_layout=legacy)
                for fn in functions.values():
                    exact(fn(), want)
                for mode in ('eager', 'graph'):
                    runners = functions
                    graphs = {}
                    if mode == 'graph':
                        for key, fn in functions.items():
                            for _ in range(3):
                                fn()
                            torch.cuda.synchronize()
                            dist.barrier()
                            with ca.capture() if key != 'rccl' else nullcontext():
                                graphs[key] = torch.cuda.CUDAGraph()
                                with torch.cuda.graph(graphs[key]):
                                    # Amortize host replay and rank-arrival skew;
                                    # measure a train of collectives on the GPU.
                                    for _ in range(args.iters):
                                        captured = fn()
                            graphs[key].replay()
                            exact(captured, want)
                        runners = {key:g.replay for key,g in graphs.items()}
                    samples = {key:[] for key in functions}
                    for round_id in range(args.rounds):
                        order = list(runners)
                        if round_id % 2:
                            order.reverse()
                        for key in order:
                            fn = runners[key]
                            for _ in range(3):
                                fn()
                            torch.cuda.synchronize()
                            dist.barrier()
                            start, end = torch.cuda.Event(enable_timing=True), torch.cuda.Event(enable_timing=True)
                            start.record()
                            for _ in range(1 if mode == 'graph' else args.iters):
                                fn()
                            end.record()
                            end.synchronize()
                            local_us = start.elapsed_time(end) * 1000 / args.iters
                            gathered = [None] * world
                            dist.all_gather_object(gathered, local_us)
                            samples[key].append(max(gathered))
                    row = dict(dtype=name, nbytes=nbytes, shape=shape, dim=dim, mode=mode,
                               world=world, timings={key:summarize(value) for key,value in samples.items()})
                    row['rccl_over_custom'] = row['timings']['rccl']['median_us'] / row['timings']['custom']['median_us']
                    rows.append(row)
                    if rank == 0:
                        print('AG_BENCH ' + json.dumps(row), flush=True)
                    del graphs, runners
    return rows


def main():
    args = arguments()
    global torch, dist, FP8_DTYPES
    import torch
    import torch.distributed as dist
    from aiter.utility.dtypes import FP8_DTYPES
    from aiter.dist.device_communicators.custom_all_reduce import CustomAllreduce
    from aiter.dist.device_communicators.communicator_pynccl import PyNcclCommunicator
    from aiter.dist import parallel_state as ps
    rank, local, world = (int(os.environ[k]) for k in ('RANK', 'LOCAL_RANK', 'WORLD_SIZE'))
    assert world in (2, 4, 8)
    torch.cuda.set_device(local)
    device = torch.device('cuda', local)
    dist.init_process_group('gloo', timeout=timedelta(seconds=180))
    nccl_group = dist.new_group(backend='nccl')
    ca = CustomAllreduce(dist.group.WORLD, local, max_size=args.max_size_mib * 1024**2,
                         enable_register_for_capturing=True)
    assert not ca.disabled and ca.transport == 'ipc', 'native custom path must be active'
    pynccl = PyNcclCommunicator(dist.group.WORLD, device)
    assert not pynccl.disabled
    group = object.__new__(ps.GroupCoordinator)
    group.world_size, group.device_group, group.unique_name = world, nccl_group, 'ag-byte-test'
    group.device_communicator = SimpleNamespace(ca_comm=ca, pynccl_comm=pynccl)
    ps._groups[group.unique_name] = weakref.ref(group)
    report = dict(rank=rank, world=world, torch=torch.__version__, hip=torch.version.hip,
                  arch=torch.cuda.get_device_properties(local).gcnArchName,
                  rccl=pynccl.nccl_version, effective_registered=ca.enable_register_for_capturing,
                  mode=args.mode, arguments=vars(args), cases=0, benchmarks=[])
    if args.mode in ('correctness', 'all'):
        report['cases'] = correctness(ca, group, args, rank, world, device)
    if args.mode in ('bench', 'all'):
        report['benchmarks'] = benchmark(ca, group, args, rank, world, device)
    torch.cuda.synchronize()
    report['native'] = {}
    for line in Path('/proc/self/maps').read_text().splitlines():
        path = line.split()[-1]
        if 'module_custom_all_reduce' in path and path.endswith('.so') and path not in report['native']:
            report['native'][path] = hashlib.sha256(Path(path).read_bytes()).hexdigest()
    assert report['native']
    report['status'] = 'passed'
    output = Path(args.output)
    output.mkdir(parents=True, exist_ok=True)
    (output / f'rank{rank}.json').write_text(json.dumps(report, indent=2) + '\n')
    print('AG_PASS ' + json.dumps({k:v for k,v in report.items() if k != 'benchmarks'}), flush=True)
    dist.barrier()
    ca.close()
    dist.destroy_process_group(nccl_group)
    dist.destroy_process_group()


if __name__ == '__main__':
    main()
