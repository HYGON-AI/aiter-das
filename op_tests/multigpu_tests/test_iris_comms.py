"""Iris AG/RS, lifecycle and RS/RMSNorm/FP8/AG fusion at TP2/4/8.

Select one --suite per torchrun invocation. Requires the pinned optional Iris
dependency. Both suites use Gloo coordination and GPU data movement.
"""
import argparse
import gc
import os
from datetime import timedelta

import torch
import torch.distributed as dist
import triton
import triton.language as tl
from aiter.ops.triton.comms import (
    IrisCommContext, all_gather, reduce_scatter,
    reduce_scatter_rmsnorm_quant_all_gather,
)
from aiter.ops.triton.comms.fused.reduce_scatter_rmsnorm_quant_all_gather import _fp8_bits


def values(rows, cols, rank, iteration, dtype, device):
    return ((torch.arange(rows * cols, device=device).reshape(rows, cols) % 7)
            + rank + iteration % 3).to(dtype)


def check(ctx, rows, cols, dtype, repeats):
    rank, world = dist.get_rank(), dist.get_world_size()
    shard = ctx.iris_ctx.empty((rows, cols), dtype=dtype)
    full = ctx.iris_ctx.empty((rows * world, cols), dtype=dtype)
    for iteration in range(repeats):
        shard.copy_(values(rows, cols, rank, iteration, dtype, shard.device))
        full.copy_(values(rows * world, cols, rank, iteration, dtype, full.device))
        gathered = all_gather(shard, ctx, num_sms=16)
        expected = torch.cat([values(rows, cols, peer, iteration, dtype, shard.device)
                              for peer in range(world)])
        torch.testing.assert_close(gathered, expected, rtol=0, atol=0)
        reduced = reduce_scatter(full, ctx, num_sms=16)
        expected = sum(values(rows * world, cols, peer, iteration, torch.float32, full.device)
                       for peer in range(world)).to(dtype).chunk(world)[rank]
        torch.testing.assert_close(reduced, expected, rtol=0, atol=0)


def run_collectives(args):
    torch.cuda.set_device(int(os.environ['LOCAL_RANK']))
    dist.init_process_group('gloo', timeout=timedelta(seconds=180))
    rank = dist.get_rank()
    assert dist.get_world_size() in (2, 4, 8)
    with IrisCommContext(256 << 20) as ctx:
        for dtype in (torch.float32, torch.float16, torch.bfloat16):
            for rows, cols in ((1, 17), (33, 129)):
                check(ctx, rows, cols, dtype, args.repeats)
                print('IRIS_CASE_PASS', rank, str(dtype), rows, cols, args.repeats, flush=True)
        # One rank violates heap ownership: every rank must reject before launch.
        valid = ctx.iris_ctx.zeros((2, 16), dtype=torch.float32)
        bad = torch.zeros_like(valid) if rank == 0 else valid
        try:
            all_gather(bad, ctx)
        except ValueError as exc:
            assert 'heap' in str(exc), str(exc)
        else:
            raise AssertionError('External input accepted')
        try:
            all_gather(valid[:, ::2], ctx)
        except ValueError:
            pass
        else:
            raise AssertionError('Strided input accepted')
        # Host barriers are intentionally unavailable inside captured graphs.
        torch.cuda.synchronize()
        stream = torch.cuda.Stream()
        graph = torch.cuda.CUDAGraph()
        try:
            with torch.cuda.graph(graph, stream=stream):
                all_gather(valid, ctx)
        except RuntimeError as exc:
            assert 'eager' in str(exc), str(exc)
        else:
            raise AssertionError('Graph capture accepted')
        del valid, bad, graph, stream
    assert not ctx.is_initialized and ctx.iris_ctx is None
    ctx.close()  # idempotent
    del ctx
    gc.collect()
    torch.cuda.empty_cache()
    torch.cuda.synchronize()
    start = torch.cuda.memory_allocated()
    for cycle in range(args.cycles):
        with IrisCommContext(2 << 20) as ctx:
            check(ctx, 3, 17, torch.float32, 1)
            try:
                full = ctx.iris_ctx.empty((5, 17), dtype=torch.float32)
                reduce_scatter(full, ctx)
            except ValueError:
                pass
            else:
                raise AssertionError('Nondivisible rows accepted')
            del full
        assert not ctx.is_initialized
        del ctx
        gc.collect()
        torch.cuda.empty_cache()
        dist.barrier()
        print('IRIS_LIFECYCLE_PASS', rank, cycle, torch.cuda.memory_allocated(), flush=True)
    assert torch.cuda.memory_allocated() <= start + (1 << 20)
    with IrisCommContext(2048) as ctx:
        x = ctx.iris_ctx.zeros((1, 17), dtype=torch.float32)
        ctx.iris_ctx.empty((1024,), dtype=torch.uint8)
        try:
            all_gather(x, ctx)
        except ValueError as exc:
            assert 'capacity' in str(exc), str(exc)
        else:
            raise AssertionError('Heap overflow accepted')
        del x
    print('IRIS_CONTRACTS_PASS', rank, dist.get_world_size(), flush=True)
    dist.destroy_process_group()


@triton.jit
def encode_kernel(x, y, count: tl.constexpr, BLOCK: tl.constexpr):
    idx = tl.program_id(0) * BLOCK + tl.arange(0, BLOCK)
    value = tl.load(x + idx, idx < count, 0)
    tl.store(y + idx, _fp8_bits(value), idx < count)


def conversion_check():
    positive = torch.arange(127, dtype=torch.uint8).view(torch.float8_e4m3fn).float()
    midpoints = (positive[1:] + positive[:-1]) / 2
    values = torch.cat([positive, midpoints, torch.nextafter(midpoints, torch.full_like(midpoints, float('inf'))),
                        torch.nextafter(midpoints, torch.full_like(midpoints, -float('inf'))), torch.tensor([449., 10000., float('inf')])])
    values = torch.cat([values, -values])
    expected = values.clamp(-448, 448).to(torch.float8_e4m3fn).view(torch.uint8)
    x = values.cuda(); y = torch.empty_like(x, dtype=torch.uint8)
    encode_kernel[(triton.cdiv(x.numel(), 256),)](x, y, x.numel(), 256)
    torch.testing.assert_close(y.cpu(), expected, rtol=0, atol=0)
    print('IRIS_FP8_BOUNDARIES_PASS', dist.get_rank(), x.numel(), flush=True)


def run_fusion(args):
    rank = int(os.environ['LOCAL_RANK']); torch.cuda.set_device(rank)
    dist.init_process_group('gloo', timeout=timedelta(seconds=180))
    world = dist.get_world_size()
    conversion_check()
    cases = 0
    with IrisCommContext(32 << 20) as ctx:
        for dtype in (torch.float32, torch.float16, torch.bfloat16):
            for rows, cols in ((1, 17), (3, 129), (2, 1024), (1, 8192)):
                x = ctx.iris_ctx.empty((rows * world, cols), dtype=dtype)
                rs = ctx.iris_ctx.empty((rows, cols), dtype=dtype)
                norm = torch.empty((rows, cols), device='cuda', dtype=torch.float32)
                fp8 = ctx.iris_ctx.empty((rows, cols), dtype=torch.float8_e4m3fn)
                g_float = ctx.iris_ctx.empty((rows * world, cols), dtype=dtype)
                g_fp8 = ctx.iris_ctx.empty((rows * world, cols), dtype=torch.float8_e4m3fn)
                gamma = ((torch.arange(cols, device='cuda') % 5) - 2).to(dtype) * .25
                pattern = ((torch.arange(x.numel(), device='cuda').reshape(x.shape) % 13) - 6).float() * .25
                for quant in (False, True):
                    for gather in (False, True):
                        for iteration in range(args.repeats):
                            x.copy_(pattern + (rank + 1) * .25 + (iteration % 3) * .125)
                            result = reduce_scatter_rmsnorm_quant_all_gather(
                                x, gamma, ctx=ctx, quant_mode='fp8_per_token' if quant else 'none',
                                do_allgather=gather, rs_buffer=rs, norm_buffer=norm,
                                fp8_out=fp8 if quant else None, gather_out=(g_fp8 if quant else g_float) if gather else None)
                            total = sum(pattern + (peer + 1) * .25 + (iteration % 3) * .125 for peer in range(world)).to(dtype)
                            expected = total.float() * torch.rsqrt(total.float().square().mean(-1, keepdim=True) + 1e-6) * gamma.float()
                            local_ref = expected.chunk(world)[rank]
                            torch.testing.assert_close(rs, total.chunk(world)[rank], rtol=0, atol=0)
                            torch.testing.assert_close(norm, local_ref, rtol=2e-5, atol=2e-5)
                            if quant:
                                # Compute the reference on CPU, including scale/division:
                                # GPU constant division may use reciprocal multiplication.
                                norm_cpu = norm.cpu()
                                scale = norm_cpu.abs().amax(-1, keepdim=True).div(448).clamp_min(1e-8)
                                qref = (norm_cpu / scale).clamp(-448, 448).to(torch.float8_e4m3fn).view(torch.uint8)
                                actual = fp8.view(torch.uint8).cpu()
                                problem = None
                                if not torch.equal(actual, qref):
                                    mismatch = (actual != qref).nonzero()[0].tolist()
                                    ij = tuple(mismatch)
                                    problem = (rank, str(dtype), rows, cols, iteration,
                                               mismatch, int(actual[ij]), int(qref[ij]),
                                               float(norm[ij]), float(scale[ij[0], 0]))
                                failures = [None] * world
                                dist.all_gather_object(failures, problem)
                                assert not any(failures), failures
                                assert result[0] is None and result[1].data_ptr() == fp8.data_ptr()
                            else:
                                assert result[0].data_ptr() == norm.data_ptr() and result[1] is None
                            if gather:
                                if quant:
                                    refs = [None] * world
                                    dist.all_gather_object(refs, fp8.view(torch.uint8).cpu())
                                    torch.testing.assert_close(result[2].view(torch.uint8).cpu(), torch.cat(refs), rtol=0, atol=0)
                                else:
                                    torch.testing.assert_close(result[2].float(), expected.to(dtype).float(), rtol=0.008, atol=0.008)
                            else:
                                assert result[2] is None
                        cases += 1
                        print('IRIS_FUSION_CASE_PASS', rank, str(dtype), rows, cols, quant, gather, args.repeats, flush=True)
        for mode in ['unknown', 'fp4_per_token']:
            try:
                reduce_scatter_rmsnorm_quant_all_gather(x, gamma, ctx=ctx, quant_mode=mode)
            except ValueError:
                pass
            else:
                raise AssertionError('Unsupported mode accepted')
    print('IRIS_FUSION_CONTRACTS_PASS', rank, world, cases, flush=True)
    dist.destroy_process_group()



def main():
    parser = argparse.ArgumentParser(description=__doc__)
    parser.add_argument('--suite', required=True, choices=['collectives', 'fusion'])
    parser.add_argument('--repeats', type=int, default=100)
    parser.add_argument('--cycles', type=int, default=20)
    args = parser.parse_args()
    if args.repeats < 1 or args.cycles < 1:
        parser.error('repeats and cycles must be >= 1')
    if args.suite == 'collectives':
        run_collectives(args)
    else:
        run_fusion(args)


if __name__ == '__main__':
    main()
