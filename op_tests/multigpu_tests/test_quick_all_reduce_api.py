"""HIP QR native contracts and Python communicator routing at TP2/4/8.

Select one --suite per torchrun invocation. The communicator suite sets its
QR environment before importing AITER; the native suite uses explicit modes.
"""
import argparse
from datetime import timedelta
import json
import os

import torch
import torch.distributed as dist

# Fixed quantization error limits; full precision uses elementwise checks.
QUANT_LIMITS = {1: (.08, .20), 2: (.08, .15), 3: (.30, .50), 4: (.60, .85)}


def expect_error(fn):
    try:
        fn()
    except (ValueError, RuntimeError):
        return
    raise AssertionError('expected validation failure')


def run_native(args):
    import aiter as ops
    rank, local, world = [int(os.environ[k]) for k in ('RANK', 'LOCAL_RANK', 'WORLD_SIZE')]
    torch.cuda.set_device(local)
    device = torch.device('cuda', local)
    dist.init_process_group('gloo', timeout=timedelta(seconds=180))
    ptr = 0
    count = 0
    maxima = {}
    try:
        ptr = ops.init_custom_qr(rank, world, 1024 * 1024)
        # vLLM single-argument get_handle form; legacy tensor open_handles.
        handle = ops.qr_get_handle(ptr)
        assert handle.device.type == 'cpu' and handle.dtype == torch.uint8 and handle.numel() == 64
        handles = [None] * world
        dist.all_gather_object(handles, handle)
        expect_error(lambda: ops.qr_open_handles(ptr, handles[:-1]))
        ops.qr_open_handles(ptr, handles)
        modes = [0, 5, 1, 2, 3] + ([4] if world == 2 else [])
        if args.mode is not None:
            modes = [args.mode]
        for dtype in (torch.float16, torch.bfloat16):
            for cast in ((False, True) if dtype == torch.bfloat16 else (False,)):
                for mode in modes:
                    for tokens, width in ((4, 512), (64, 4096)):
                        x = torch.empty((tokens, width), dtype=dtype, device=device)
                        ar = torch.empty_like(x)
                        residual = torch.empty_like(x)
                        residual_out = torch.empty_like(x)
                        norm = torch.empty_like(x)
                        weight = (torch.arange(width, device=device).float() % 7 / 8 + .5).to(dtype)
                        base = (torch.arange(x.numel(), device=device).reshape(x.shape).float() % 37 - 18) / 32
                        key = f'{dtype}/cast={cast}/mode={mode}/{tokens}x{width}'
                        tol = .005 if dtype == torch.float16 else .04

                        def fill(i):
                            amplitude = (2 ** (i % 3)) * (-1 if i % 2 else 1)
                            inputs = [((base + r / 32) * amplitude).to(dtype) for r in range(world)]
                            x.copy_(inputs[rank])
                            residual.fill_(.125 * amplitude)
                            return torch.stack([v.float() for v in inputs]).sum(0)

                        def invoke():
                            ops.qr_all_reduce(ptr, x, ar, mode, cast)
                            ops.qr_all_reduce_rmsnorm(ptr, x, residual, residual_out, norm,
                                                     weight, 1e-6, width, mode, cast)

                        def validate(reference):
                            assert torch.isfinite(ar).all() and torch.isfinite(norm).all()
                            error = ar.float() - reference
                            nrmse = float(error.square().mean().sqrt() / reference.square().mean().sqrt().clamp_min(1e-6))
                            maxerr = float(error.abs().max() / reference.abs().max().clamp_min(1e-6))
                            maxima[key] = [max(nrmse, maxima.get(key, [0, 0])[0]), max(maxerr, maxima.get(key, [0, 0])[1])]
                            if mode in (0, 5):
                                torch.testing.assert_close(ar.float(), reference, rtol=tol, atol=tol, msg=key)
                            else:
                                a, b = QUANT_LIMITS[mode]
                                assert nrmse <= a and maxerr <= b, (key, nrmse, maxerr)
                            # Separate QR output is the controlled quantized AR reference.
                            z = ar.float() + residual.float()
                            expected = z * torch.rsqrt(z.square().mean(-1, keepdim=True) + 1e-6) * weight.float()
                            torch.testing.assert_close(residual_out.float(), z, rtol=tol, atol=tol, msg=key + '/residual')
                            torch.testing.assert_close(norm.float(), expected, rtol=tol, atol=tol, msg=key + '/norm')

                        reference = fill(0)
                        invoke()
                        validate(reference)
                        graph = torch.cuda.CUDAGraph()
                        with torch.cuda.graph(graph):
                            invoke()
                        for i in range(args.repeats):
                            reference = fill(i)
                            graph.replay()
                            validate(reference)
                        del graph
                        x.zero_()
                        ops.qr_all_reduce(ptr, x, ar, mode, cast)
                        assert torch.isfinite(ar).all() and not ar.count_nonzero(), key + '/zero'
                        x.fill_(1e-5 * (-1 if rank % 2 else 1))
                        ops.qr_all_reduce(ptr, x, ar, mode, cast)
                        assert torch.isfinite(ar).all(), key + '/tiny-cancellation'
                        torch.testing.assert_close(ar.float(), torch.zeros_like(ar.float()),
                                                   rtol=0, atol=1e-4, msg=key + '/tiny-cancellation')
                        count += 1
                        print('QR_CASE_PASS', rank, key, maxima[key], flush=True)
        expect_error(lambda: ops.qr_all_reduce(ptr, x, torch.empty_like(x, dtype=torch.float32), 0))
        expect_error(lambda: ops.qr_all_reduce(ptr, x, ar, 99))
        if world != 2:
            expect_error(lambda: ops.qr_all_reduce(ptr, x, ar, 4))
        torch.cuda.synchronize()
        dist.barrier()
        ops.qr_destroy(ptr)
        ptr = 0
        # Upstream explicit host-pointer handle API; alternate allocation sizes
        # to catch a static per-instance buffer-size calculation.
        for i in range(20):
            ptr = ops.init_custom_qr(rank, world, (1 + i % 2) * 1024 * 1024)
            handle = torch.empty(64, dtype=torch.uint8, device='cpu')
            ops.qr_get_handle(ptr, handle.data_ptr())
            dist.all_gather_object(handles, handle)
            ops.qr_open_handles(ptr, [h.data_ptr() for h in handles])
            x = torch.full((4096,), rank + 1., dtype=torch.float16, device=device)
            ar = torch.empty_like(x)
            ops.qr_all_reduce(ptr, x, ar, 0)
            torch.testing.assert_close(ar, torch.full_like(ar, world * (world + 1) / 2), rtol=0, atol=0)
            torch.cuda.synchronize()
            dist.barrier()
            ops.qr_destroy(ptr)
            ptr = 0
        print('QR_CONTRACT_PASS ' + json.dumps(dict(rank=rank, world=world, cases=count,
              replays=args.repeats, rebuilds=20, max_errors=maxima)), flush=True)
    finally:
        if ptr:
            ops.qr_destroy(ptr)
        dist.destroy_process_group()


def run_communicator():
    os.environ['AITER_QUICK_REDUCE_QUANTIZATION'] = 'FP'
    os.environ['AITER_QUICK_REDUCE_MAX_SIZE_BYTES_MB'] = '1'
    from aiter.dist.device_communicators.quick_all_reduce import QuickAllReduce
    from aiter.dist.device_communicators.communicator_cuda import CudaCommunicator
    rank, local, world = [int(os.environ[k]) for k in ('RANK', 'LOCAL_RANK', 'WORLD_SIZE')]
    # Existing FP routing requires 16 MiB for TP8, versus 1 MiB for TP2/TP4.
    # Exercise the real threshold instead of overriding the production policy.
    size_mb = 16 if world == 8 else 1
    tokens = size_mb * 256
    os.environ['AITER_QUICK_REDUCE_MAX_SIZE_BYTES_MB'] = str(size_mb)
    torch.cuda.set_device(local)
    dist.init_process_group('gloo', timeout=timedelta(seconds=180))
    device = torch.device('cuda', local)
    os.environ['AITER_AR_TRANSPORT'] = 'fabric'
    disabled = QuickAllReduce(dist.group.WORLD, device)
    assert disabled.disabled and disabled._ptr == 0
    disabled.close()
    os.environ['AITER_AR_TRANSPORT'] = 'ipc'
    first = QuickAllReduce(dist.group.WORLD, device)
    second = QuickAllReduce(dist.group.WORLD, device)
    assert not first.disabled and not second.disabled, 'QR high-level path must be enabled'
    try:
        x = torch.empty((tokens, 2048), dtype=torch.float16, device=device)
        residual = torch.full_like(x, .125)
        weight = torch.ones(2048, dtype=x.dtype, device=device)
        assert first.should_quick_allreduce(x)
        if world == 8:
            assert not first.should_quick_allreduce(x[:256])
        assert not first.should_quick_allreduce(x.t())
        assert not first.should_quick_allreduce(x.cpu())
        assert not first.should_quick_allreduce(x[:0])
        assert not first.should_quick_allreduce(torch.empty((tokens + 1, 2048), device=device, dtype=x.dtype))
        assert first.should_quick_allreduce_rmsnorm(x, residual, weight, 2048)
        assert not first.should_quick_allreduce_rmsnorm(x, residual, weight, 0)
        assert not first.should_quick_allreduce_rmsnorm(x, residual[:1], weight, 2048)
        route = CudaCommunicator.__new__(CudaCommunicator)
        route.world_size, route.ca_comm, route.qr_comm = world, None, first
        route._ar_1stage_max_kb, route._ar_1stage_override = -1, False
        # A fallback would call all_reduce; make that an explicit test failure.
        route.all_reduce = lambda *a, **k: (_ for _ in ()).throw(AssertionError('QR route fell back'))
        def invoke():
            y, z = route.fused_allreduce_rmsnorm(x, residual, weight, 1e-6)
            other = second.quick_all_reduce(x)
            return y, z, other
        x.fill_(rank + 1.)
        invoke()
        graph = torch.cuda.CUDAGraph()
        with torch.cuda.graph(graph):
            y, z, other = invoke()
        for i in range(100):
            x.fill_((rank + 1.) * (1 + i % 3))
            graph.replay()
            expected = world * (world + 1) / 2 * (1 + i % 3)
            torch.testing.assert_close(other, torch.full_like(other, expected), rtol=0, atol=0)
            torch.testing.assert_close(z, torch.full_like(z, expected + .125), rtol=0, atol=0)
            torch.testing.assert_close(y, torch.ones_like(y), rtol=.005, atol=.005)
        del graph
        torch.cuda.synchronize()
        dist.barrier()
        first.close(); first.close()
        assert first.disabled and not first.should_quick_allreduce(x)
        import aiter as ops
        for entry in ('init_custom_qr', 'qr_get_handle', 'qr_open_handles'):
            saved = getattr(ops, entry)
            if rank == 0:
                def fail(*args, **kwargs):
                    raise RuntimeError('injected QR initialization failure')
                setattr(ops, entry, fail)
            try:
                try:
                    QuickAllReduce(dist.group.WORLD, device)
                except RuntimeError as exc:
                    assert 'failed collectively' in str(exc), str(exc)
                else:
                    raise AssertionError('initialization failure was not collective')
            finally:
                setattr(ops, entry, saved)
            dist.barrier()
        print('QR_HIGH_LEVEL_PASS ' + json.dumps(dict(rank=rank, world=world, replays=100)), flush=True)
    finally:
        first.close(); second.close()
        dist.destroy_process_group()



def main():
    parser = argparse.ArgumentParser(description=__doc__)
    parser.add_argument('--suite', required=True, choices=['native', 'communicator'])
    parser.add_argument('--repeats', type=int, default=100)
    parser.add_argument('--mode', type=int, default=None)
    args = parser.parse_args()
    if args.repeats < 2:
        parser.error('repeats must be >= 2')
    if args.mode is not None and args.suite != 'native':
        parser.error('--mode requires --suite native')
    if args.suite == 'native':
        run_native(args)
    else:
        run_communicator()


if __name__ == '__main__':
    main()
