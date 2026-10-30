# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Full L03 matrix, chunked independent references and fixed-buffer timings.

python op_tests/op_benchmarks/bench_moe_routing.py --correctness --output results
python op_tests/op_benchmarks/bench_moe_routing.py --bench --rounds 7 --output results
No shape is silently skipped or reduced. Failures/OOM are recorded and exit nonzero.
"""
import argparse
import gc
import hashlib
import importlib.util
import json
import os
from pathlib import Path
import statistics
import time

import torch
from aiter.ops import moe_routing as op
from aiter.jit import core

spec=importlib.util.spec_from_file_location('l03_reference',Path(__file__).resolve().parents[1]/'test_moe_routing.py')
ref=importlib.util.module_from_spec(spec);spec.loader.exec_module(ref)


def verify_scatter(x,out,scale,buffers,smooth,mode,chunk=8192):
    for lo in range(0,out.shape[0],chunk):
        hi=min(out.shape[0],lo+chunk);tokens=buffers.token_ids[lo:hi].long();experts=buffers.m_indices[lo:hi].long();valid=tokens>=0
        src=x[tokens.clamp_min(0)]
        if mode=='none':
            expected=torch.where(valid[:,None],src,torch.zeros_like(src))
            assert torch.equal(out[lo:hi],expected), f'scatter mismatch rows {lo}:{hi}'
        else:
            sm=smooth[experts.clamp_min(0)] if smooth is not None else None
            q,s=ref.quant_reference(src,sm,mode)
            qbytes=torch.where(valid[:,None],q.view(torch.uint8),torch.zeros_like(q.view(torch.uint8)))
            s=torch.where(valid[:,None],s,torch.ones_like(s))
            assert torch.equal(out[lo:hi].view(torch.uint8),qbytes),f'quant byte mismatch rows {lo}:{hi}'
            assert torch.equal(scale[lo:hi],s),f'quant scale mismatch rows {lo}:{hi}'
            # Encoding and scale checked exactly above; also check dequantization.
            z=src.float() if sm is None else src.float()*sm
            restored=q.float()*s
            limit=s*.5001 if mode=='int8' else z.abs()*.063+s*(2**-9)
            assert torch.all((restored[valid]-z[valid]).abs()<=limit[valid]+1e-6)


def verify_gather(out,mid,weights,buffers,residual=None,start=0,end=None,res_scale=.5,chunk=2048):
    M,H=out.shape;K=weights.shape[1];end=M if end is None else end
    max_error=0.;max_bound_ratio=0.
    for lo in range(0,M,chunk):
        hi=min(M,lo+chunk);shape=(hi-lo,H)
        acc=torch.zeros(shape,device=out.device,dtype=torch.float32)
        exact=torch.zeros(shape,device=out.device,dtype=torch.float64);absolute=exact.clone()
        a=max(lo,start);b=min(hi,end)
        if residual is not None and a<b:
            rv=residual[a-start:b-start]
            acc[a-lo:b-lo]=rv.float()*res_scale
            exact[a-lo:b-lo]=rv.double()*res_scale;absolute[a-lo:b-lo]=exact[a-lo:b-lo].abs()
        for k in range(K):
            rows=buffers.inv_perm[lo:hi,k].long();valid=rows>=0
            values=mid[rows.clamp_min(0)].float();w=weights[lo:hi,k,None]
            term=torch.where(valid[:,None],values*w,torch.zeros_like(values))
            acc=acc+term
            term64=torch.where(valid[:,None],values.double()*w.double(),torch.zeros_like(exact))
            exact=exact+term64;absolute=absolute+term64.abs()
        expected=acc.to(out.dtype)
        tol={torch.bfloat16:(.008,.008),torch.float16:(.001,.001),torch.float32:(2e-6,2e-6)}[out.dtype]
        torch.testing.assert_close(out[lo:hi],expected,rtol=tol[0],atol=tol[1])
        u=2**-24;n=2*K+4;gamma=n*u/(1-n*u)
        bound=gamma*absolute+torch.finfo(out.dtype).eps*acc.double().abs()+torch.finfo(out.dtype).tiny
        error=(out[lo:hi].double()-exact).abs()
        assert torch.all(error<=bound),f'FP64 error bound exceeded tokens {lo}:{hi}'
        max_error=max(max_error,float(error.max()));max_bound_ratio=max(max_bound_ratio,float((error/bound.clamp_min(1e-30)).max()))
    return dict(max_fp64_error=max_error,max_bound_ratio=max_bound_ratio)


def make_case(case,index):
    torch.manual_seed(1000+index)
    M,H,K,E=case['M'],case['H'],case['K'],case['E'];eg=case['E_global']
    dtype=torch.bfloat16;id_dtype=torch.int32 if index%2 else torch.int64
    ids=torch.randint(eg,(M,K),device='cuda',dtype=id_dtype)
    if K>1:ids[:,1]=ids[:,0] # duplicate routes are distinct slots.
    mapping=None
    if case['EP']>1:
        mapping=torch.full((eg,),-1,device='cuda',dtype=torch.int32)
        mapping[-E:]=torch.arange(E,device='cuda',dtype=torch.int32)
        ids.view(-1)[::127]=-1
    weights=torch.rand(M,K,device='cuda')*2-1;weights.view(-1)[::13]=0
    x=torch.randn(M,H,device='cuda',dtype=dtype)
    b=op.allocate_moe_routing(ids,E,case['alignment']);mode=case['mode']
    out_dtype=dtype if mode=='none' else torch.int8 if mode=='int8' else torch.float8_e4m3fn
    expanded=torch.empty(b.route_ids.numel(),H,device='cuda',dtype=out_dtype)
    scale=None if mode=='none' else torch.empty(expanded.shape[0],1,device='cuda')
    smooth=None if mode=='none' else .25+torch.rand(E,H,device='cuda')*1.75
    y=None if case['family']=='scatter' else torch.empty(M,case['Hout'],device='cuda',dtype=dtype)
    start=end=0;residual=None
    if case['family']=='gather':
        sp=case['SP'];chunk=(M+sp-1)//sp;start=min(M,(sp-1)*chunk);end=M
        residual=torch.randn(end-start,H,device='cuda',dtype=dtype)
    def prepare():b.prepare(ids,weights,mapping)
    def scatter():op.moe_routing_scatter_out(expanded,scale,x,b.token_ids,b.m_indices,smooth,mode)
    def gather():op.moe_routing_gather_out(y,expanded,weights,b.inv_perm,b.m_indices,residual=residual,res_scale=.5,residual_start=start,residual_end=end)
    def full():
        prepare()
        if case['family']!='gather':scatter()
        if y is not None:gather()
    prepare();scatter()
    funcs={'prepare':prepare,'scatter':scatter}
    if y is not None:funcs['gather']=gather
    funcs['full']=full
    return dict(ids=ids,weights=weights,map=mapping,x=x,b=b,expanded=expanded,scale=scale,smooth=smooth,y=y,residual=residual,start=start,end=end,funcs=funcs)


def time_case(state,rounds,iters):
    funcs=state['funcs'];graphs={}
    for name,fn in funcs.items():
        for _ in range(3):fn()
        torch.cuda.synchronize();graph=torch.cuda.CUDAGraph()
        with torch.cuda.graph(graph):fn()
        graphs[name]=graph
    timings={mode:{name:[] for name in funcs} for mode in ['eager','graph']}
    for round_id in range(rounds):
        order=[(mode,name) for mode in timings for name in funcs]
        if round_id%2:order.reverse()
        for mode,name in order:
            fn=funcs[name] if mode=='eager' else graphs[name].replay
            s=torch.cuda.Event(enable_timing=True);e=torch.cuda.Event(enable_timing=True)
            s.record()
            for _ in range(iters):fn()
            e.record();e.synchronize();timings[mode][name].append(s.elapsed_time(e)*1000/iters)
    return {'iterations':iters,'rounds_us':timings,'median_us':{mode:{name:statistics.median(v) for name,v in stages.items()} for mode,stages in timings.items()},'cv':{mode:{name:statistics.pstdev(v)/statistics.mean(v) for name,v in stages.items()} for mode,stages in timings.items()}}


def main():
    parser=argparse.ArgumentParser();parser.add_argument('--output',required=True)
    parser.add_argument('--correctness',action='store_true');parser.add_argument('--bench',action='store_true')
    parser.add_argument('--rounds',type=int,default=7);parser.add_argument('--family',choices=['all','gather','scatter','init_finalize'],default='all')
    parser.add_argument('--case-id');parser.add_argument('--start',type=int,default=0);parser.add_argument('--stop',type=int)
    args=parser.parse_args();folder=Path(args.output);folder.mkdir(parents=True,exist_ok=True)
    assert args.correctness or args.bench
    if args.bench:assert args.rounds>=7
    torch.set_num_threads(8)
    cases=ref.routing_cases();(folder/'manifest.json').write_text(json.dumps(cases,indent=2))
    failures=0;executed=0
    for index,case in enumerate(cases):
        if index<args.start or (args.stop is not None and index>=args.stop):continue
        if args.family!='all' and case['family']!=args.family:continue
        if args.case_id and args.case_id!=case['id']:continue
        started=time.monotonic();record=dict(case);record['index']=index
        state=None
        try:
            cap=case['M']*case['K']+case['E']*(case['alignment']-1)
            estimated=cap*case['H']*(2 if case['mode']=='none' else 1)+case['M']*(case['H']+case['Hout'])*2+cap*48+(512<<20)
            free,total=torch.cuda.mem_get_info();record.update(estimated_bytes=estimated,free_bytes_before=free,total_bytes=total)
            if estimated>free:raise torch.OutOfMemoryError(f'full shape estimate {estimated} > free {free}')
            state=make_case(case,index);b=state['b'];record['ids_dtype']=str(state['ids'].dtype)
            record['capacity']=b.route_ids.numel();record['valid_rows']=int(b.valid_rows);record['span_rows']=int(b.span_rows)
            if args.correctness:
                expected=ref.metadata_reference_vectorized(state['ids'],state['weights'],case['E'],state['map'],case['alignment'],capacity=b.route_ids.numel())
                ref.check_metadata(b,expected);del expected
                verify_scatter(state['x'],state['expanded'],state['scale'],b,state['smooth'],case['mode'])
                record['init_status']='PASS'
                if state['y'] is not None:
                    state['funcs']['gather']()
                    record.update(verify_gather(state['y'],state['expanded'],state['weights'],b,state['residual'],state['start'],state['end']))
                    record['finalize_status']='PASS'
            if args.bench:
                iters=2 if estimated>256<<20 else 10
                record['performance']=time_case(state,args.rounds,iters)
            record['status']='PASS'
        except Exception as exc:
            import traceback
            failures+=1;record['status']='OOM' if isinstance(exc,torch.OutOfMemoryError) else 'FAIL'
            record['error']=str(exc);record['traceback']=traceback.format_exc()
        record['seconds']=time.monotonic()-started
        with (folder/'results.jsonl').open('a') as f:f.write(json.dumps(record)+'\n')
        executed+=1;print(json.dumps({k:record[k] for k in ['index','id','status','seconds']}),flush=True)
        del state;gc.collect();torch.cuda.empty_cache()
        if record['status']=='FAIL':break # preserve failing shape, never declare later cases passed.
    module=core.get_module('module_moe_utils')
    provenance={'torch':torch.__version__,'hip':torch.version.hip,'gpu':str(torch.cuda.get_device_properties(0)),
                'visible_device':os.environ.get('HIP_VISIBLE_DEVICES'),'elf':module.__file__,
                'elf_sha256':hashlib.sha256(Path(module.__file__).read_bytes()).hexdigest(),
                'csrc':core.AITER_CSRC_DIR,'executed':executed,'failures':failures,'jit_dir':os.environ.get('AITER_JIT_DIR')}
    (folder/'provenance.json').write_text(json.dumps(provenance,indent=2));print(json.dumps(provenance),flush=True)
    raise SystemExit(1 if failures else 0)


if __name__=='__main__':main()
