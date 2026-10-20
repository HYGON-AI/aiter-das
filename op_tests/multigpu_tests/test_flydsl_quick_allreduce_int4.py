# SPDX-License-Identifier: MIT
"""Run with torchrun; real public-API correctness and performance checks."""
import argparse
import json
import math
import os
import statistics
from datetime import timedelta
from pathlib import Path
from unittest.mock import patch

import torch
import torch.distributed as dist


def metrics(y, ref):
    y = y.float(); ref = ref.float()
    error = (y-ref).square()
    power = ref.square()
    def score(e, p):
        return 999. if e == 0 else 10*math.log10(p/e) if p else -999.
    n = y.numel(); tile = 16384; full = n//tile*tile
    tiles = []
    if full:
        es = error[:full].reshape(-1, tile).mean(1).cpu().tolist()
        ps = power[:full].reshape(-1, tile).mean(1).cpu().tolist()
        tiles += [score(e, p) for e, p in zip(es, ps)]
    if full != n:
        tiles.append(score(error[full:].mean().item(), power[full:].mean().item()))
    return dict(finite=bool(torch.isfinite(y).all()), sqnr_db=score(error.mean().item(), power.mean().item()),
                min_tile_sqnr_db=min(tiles), max_abs=(y-ref).abs().max().item(),
                mismatch_ratio=(~torch.isclose(y,ref,rtol=.1,atol=.1)).float().mean().item())


def main():
    p=argparse.ArgumentParser()
    p.add_argument('--suite',choices=['smoke','large','perf'],default='smoke')
    p.add_argument('--grid-cap',type=int)
    p.add_argument('--output',required=True)
    a=p.parse_args()
    rank=int(os.environ['LOCAL_RANK']);world=int(os.environ['WORLD_SIZE'])
    torch.set_num_threads(1);torch.cuda.set_device(rank)
    dist.init_process_group('gloo',timeout=timedelta(seconds=240))
    gpu_group=dist.new_group(backend='nccl',timeout=timedelta(seconds=240))
    from aiter.ops.flydsl import QuickAllReduceInt4
    from aiter.ops.flydsl.quick_allreduce_int4_ipc import UncachedIpcHeap
    import aiter.ops.flydsl.quick_allreduce_int4 as host
    root=Path(a.output);root.mkdir(parents=True,exist_ok=True)
    rows=[];checks=[]
    def save():
        (root/f'results_rank{rank}.json').write_text(json.dumps(dict(rows=rows,checks=checks),indent=2))
    def expect_failure(fn, label):
        try:fn()
        except (ValueError,RuntimeError,TypeError):checks.append(label);save()
        else:raise AssertionError('expected failure: '+label)
    def new(**kwargs):
        return QuickAllReduceInt4(group=dist.group.WORLD,device=rank,rank=rank,world_size=world,
                                 grid_cap=a.grid_cap,**kwargs)
    comm=None
    try:
        if a.suite=='smoke':
            expect_failure(lambda:QuickAllReduceInt4(group=dist.group.WORLD,device=rank,rank=-1 if rank==0 else rank,world_size=world),'collective_bad_rank')
            expect_failure(lambda:new(small_payload_policy='bad' if rank==0 else 'fp'),'collective_bad_policy')
            expect_failure(lambda:new(super_tile=1 if rank==0 else 8),'collective_config_mismatch')
            original_alloc=UncachedIpcHeap.alloc_uncached
            def fail_alloc(size):
                if rank==0:raise RuntimeError('injected allocation failure')
                return original_alloc(size)
            with patch.object(UncachedIpcHeap,'alloc_uncached',side_effect=fail_alloc):
                expect_failure(new,'collective_allocation_failure')
        comm=new()
        grids={st:e.grid for st,e in comm._by_st.items()}
        checks.append(dict(grids=grids,small_payload_bytes=comm.small_payload_bytes,arch=comm.arch))
        stream=torch.cuda.Stream()
        warm=torch.zeros(16384,device='cuda',dtype=torch.bfloat16);warm_out=torch.empty_like(warm)
        if a.suite=='smoke':
            original_compile=host.flyc.compile
            def fail_compile(*args,**kwargs):
                if rank==0:raise RuntimeError('injected compiler failure')
                return original_compile(*args,**kwargs)
            with patch.object(host.flyc,'compile',side_effect=fail_compile):
                expect_failure(lambda:comm.compile(warm,warm_out,stream),'collective_preload_failure')
        comm.compile(warm,warm_out,stream);stream.synchronize();dist.barrier()
        checks.append('compile_retry_and_warmup');save()
        if a.suite=='smoke':
            expect_failure(lambda:comm.allreduce(warm,warm,stream),'overlap_rejected')
            expect_failure(lambda:comm.allreduce(warm.float(),warm_out,stream),'dtype_rejected')
            expect_failure(lambda:comm.allreduce(warm[:7],warm_out[:7],stream),'size_rejected')
            expect_failure(lambda:comm.allreduce(warm[1:9],warm_out[:8],stream),'alignment_rejected')
            empty=torch.empty(0,device='cuda',dtype=torch.bfloat16)
            comm.allreduce(empty,empty,stream);checks.append('empty_noop')
        def case(n,seed,mode='eager',fill='normal'):
            if fill=='normal':
                if n<=24:
                    cpu=(torch.randn(n,generator=torch.Generator().manual_seed(seed*world+rank))*.1).bfloat16()
                    inp=cpu.cuda()
                else:
                    torch.manual_seed(seed*world+rank);inp=(torch.randn(n,device='cuda')*.1).bfloat16()
            else:
                value={'zeros':0.,'positive':2.**-8,'negative':-2.**-8,'overflow':512. if rank==0 else 0.}[fill]
                inp=torch.full((n,),value,device='cuda',dtype=torch.bfloat16)
            ref=inp.float();dist.all_reduce(ref,group=gpu_group)
            storage=torch.full((n+128,),53.,device='cuda',dtype=torch.bfloat16);out=storage[64:64+n];out.fill_(float('nan'))
            torch.cuda.synchronize();dist.barrier()
            if mode=='graph':
                g=torch.cuda.CUDAGraph()
                with torch.cuda.graph(g,stream=stream):comm.allreduce(inp,out,stream)
                with torch.cuda.stream(stream):g.replay()
                stream.synchronize();del g
            else:comm.allreduce(inp,out,stream);stream.synchronize()
            m=metrics(out,ref);m.update(n=n,seed=seed,mode=mode,fill=fill,rank=rank,world=world,arch=comm.arch,
                backend='hip_fp' if n*2<=comm.small_payload_bytes else 'int4',guard_ok=bool((storage[:64]==53).all() and (storage[64+n:]==53).all()))
            if m['backend']=='hip_fp':m['bf16_reference_equal']=bool(torch.equal(out,ref.bfloat16()))
            rows.append(m);save();print(json.dumps(m),flush=True)
            assert m['finite'] and m['guard_ok'] and m['sqnr_db']>=18 and m['min_tile_sqnr_db']>=8 and m['mismatch_ratio']<=.5,m
            if n<=24:
                # Native CodecFP reduces in rank order with BF16 rounding at
                # every addition. Compare that contract separately from the
                # FP32 mathematical reference used for SQNR above.
                expected=torch.zeros(n,dtype=torch.bfloat16)
                for r in range(world):
                    expected.add_((torch.randn(n,generator=torch.Generator().manual_seed(seed*world+r))*.1).bfloat16())
                m['native_bf16_equal']=bool(torch.equal(out.cpu(),expected))
                save();assert m['native_bf16_equal'],m
            dist.barrier()
        if a.suite=='smoke':
            for n in [8,24]:
                for seed in [1001,3008,4008,4010,4011,4013,4014,4015]:case(n,seed,'graph')
            for n in [16376,16384,16392,grids[1]*16384-8,grids[1]*16384+8,grids[8]*8*16384+8]:case(n,17)
            for fill in ['zeros','positive','negative','overflow']:case(32768,21,fill=fill)
        elif a.suite=='large':
            for n in [1048576,4194304,16777216,67108864,167772160,167772168]:case(n,31)
            # 128 ordered replays with device-side changing input and no CPU
            # barrier between launches; exercises protocol colors repeatedly.
            n=grids[8]*8*16384+8
            torch.manual_seed(91+rank);inp=(torch.randn(n,device='cuda')*.1).bfloat16()
            expected=inp.clone();out=torch.empty_like(inp)
            for _ in range(128):expected.add_(1/1024)
            ref=expected.float();dist.all_reduce(ref,group=gpu_group)
            torch.cuda.synchronize();dist.barrier()
            g=torch.cuda.CUDAGraph()
            with torch.cuda.graph(g,stream=stream):
                inp.add_(1/1024);comm.allreduce(inp,out,stream)
            with torch.cuda.stream(stream):
                for _ in range(128):g.replay()
            stream.synchronize();del g
            m=metrics(out,ref);m.update(mode='graph_stress_128',n=n,input_equal=bool(torch.equal(inp,expected)),rank=rank,world=world,arch=comm.arch)
            rows.append(m);save();assert m['input_equal'] and m['finite'] and m['sqnr_db']>=18 and m['min_tile_sqnr_db']>=8,m
        else:
            from aiter.ops import quick_all_reduce as qr
            ptr=qr.init_custom_qr(rank,world,64*1024*1024)
            handles=[None]*world;dist.all_gather_object(handles,qr.qr_get_handle(ptr));qr.qr_open_handles(ptr,handles)
            try:
                for n in [16384,131072,1048576,4194304,16777216,33554432]:
                    torch.manual_seed(300+rank);inp=(torch.randn(n,device='cuda')*.1).bfloat16();out=torch.empty_like(inp)
                    ref=inp.float();dist.all_reduce(ref,group=gpu_group);torch.cuda.synchronize()
                    def rccl():
                        out.copy_(inp);dist.all_reduce(out,group=gpu_group)
                    backends={'flydsl':lambda:comm.allreduce(inp,out),
                              'hip_fp':lambda:qr.qr_all_reduce(ptr,inp,out,0,False),'rccl_bf16':rccl}
                    for name,call in backends.items():
                        for _ in range(3):call()
                        torch.cuda.synchronize();m=metrics(out,ref)
                        assert m['finite'] and m['sqnr_db']>=18 and m['min_tile_sqnr_db']>=8,m
                        dist.barrier();g=torch.cuda.CUDAGraph()
                        with torch.cuda.graph(g):
                            for _ in range(16):call()
                        samples=[]
                        for _ in range(20):
                            dist.barrier();start=torch.cuda.Event(enable_timing=True);end=torch.cuda.Event(enable_timing=True)
                            start.record();g.replay();end.record();end.synchronize()
                            samples.append(start.elapsed_time(end)*1000/16)
                        del g
                        # Collective latency is the slowest participating rank.
                        gathered=[None]*world;dist.all_gather_object(gathered,samples)
                        worst=[max(v[i] for v in gathered) for i in range(20)]
                        row=dict(mode='perf',backend=name,n=n,rank=rank,world=world,arch=comm.arch,
                                 samples_us=samples,collective_samples_us=worst,median_us=statistics.median(worst),
                                 p95_us=sorted(worst)[18],max_us=max(worst),cv=statistics.pstdev(worst)/statistics.mean(worst),correctness=m)
                        rows.append(row);save();print(json.dumps(row),flush=True)
            finally:
                torch.cuda.synchronize();dist.barrier();qr.qr_destroy(ptr)
        comm.close();comm.close();checks.append('close_idempotent')
        expect_failure(lambda:comm.allreduce(warm,warm_out),'use_after_close')
        if a.suite=='smoke':
            comm=new(super_tile=1);comm.compile(warm,warm_out,stream);stream.synchronize();comm.close();checks.append('release_rebuild_st1')
        save();(root/f'PASS_rank{rank}').write_text('PASS\n');print('PUBLIC_INT4_PASS',rank,a.suite,flush=True)
    finally:
        if comm is not None:comm.close()
        dist.destroy_process_group(gpu_group);dist.destroy_process_group()


if __name__=='__main__':main()
