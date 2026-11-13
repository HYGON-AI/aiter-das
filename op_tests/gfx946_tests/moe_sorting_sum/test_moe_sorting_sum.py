# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Small eager CPU-reference checks; only stdlib, torch and installed AITER.

Run from any directory, after selecting the intended installed package:
  python test_moe_sorting_sum.py --op sorting --suite full
  python test_moe_sorting_sum.py --op sum --suite full --dtype bf16
PMD: set GPU_ARCHS=gfx946, PMD_PATH=/opt/rocm/pmd and matching LD_LIBRARY_PATH;
GPU_CHIP=sb or sbx2 selects the model. The test removes it after initialization.
--expect-xcds checks HSA topology independently; C++ uses HIP numXcc.
--suite route --die-mode linear --chunk 1/2 exercises multi-die dispatch.
--route-path mp selects sorting P0/P1/P23; otherwise oneshot + buffer clear.
Each case invokes the DUT once, without warmup, timing loops or old results.
JSON is optional output only. Graph, hardware performance and HBM placement
are not covered; dual-XCD execution requires separate PMD TG evidence.
"""
import argparse
import ctypes
import ctypes.util
import hashlib
import json
import os
from pathlib import Path
import torch
import aiter
from aiter.fused_moe import moe_sorting

DTYPES = dict(fp16=torch.float16, bf16=torch.bfloat16, fp32=torch.float32)
def topology():
    class Agent(ctypes.Structure):
        _fields_ = [('handle', ctypes.c_uint64)]
    hsa = ctypes.CDLL(ctypes.util.find_library('hsa-runtime64') or 'libhsa-runtime64.so.1')
    callback_type = ctypes.CFUNCTYPE(ctypes.c_uint32, Agent, ctypes.c_void_p)
    hsa.hsa_agent_get_info.argtypes = [Agent, ctypes.c_int, ctypes.c_void_p]
    hsa.hsa_iterate_agents.argtypes = [callback_type, ctypes.c_void_p]
    found = []
    @callback_type
    def visit(agent, unused):
        device = ctypes.c_uint32()
        status = hsa.hsa_agent_get_info(agent, 17, ctypes.byref(device))
        if status or device.value != 1:
            return status
        name, xcds = ctypes.create_string_buffer(64), ctypes.c_uint32()
        assert hsa.hsa_agent_get_info(agent, 0, name) == 0
        status = hsa.hsa_agent_get_info(agent, 0xA111, ctypes.byref(xcds))
        found.append(dict(name=name.value.decode(), xcds=xcds.value, status=status))
        return 0
    assert hsa.hsa_init() == 0
    try:
        assert hsa.hsa_iterate_agents(visit, None) == 0
    finally:
        assert hsa.hsa_shut_down() == 0
    return found


def sorting_case(c, dtype):
    m, e, k, b = (c[x] for x in ('m', 'e', 'k', 'b'))
    ids = (torch.arange(m)[:, None] * 3 + torch.arange(k)[None, :]).remainder(e).int()
    if c.get('invalid') and m:
        ids[0, 0] = -1
        if m > 1: ids[1, 0] = e
    if c.get('all_invalid'): ids.fill_(-1)
    weights = (torch.arange(m*k).reshape(m, k).float() + 1) / 32
    mask = None
    if c.get('mask'):
        mask = (torch.arange(e).remainder(3) != 1).int()
    if c.get('all_masked'): mask = torch.zeros(e, dtype=torch.int32)
    counts=[]; offsets=[]; expect_ids=[]; expect_weights=[]; expect_experts=[]
    pad = m | (k << 24)
    local = 0
    for expert in range(e):
        offsets.append(len(expect_ids))
        routes = (ids == expert).nonzero().tolist() if mask is None or mask[expert] else []
        counts.append(len(routes))
        n = ((len(routes) + b - 1) // b) * b
        expect_ids.extend([t | (rank << 24) for t, rank in routes] + [pad] * (n-len(routes)))
        expect_weights.extend([weights[t, rank].item() for t, rank in routes] + [0.]*(n-len(routes)))
        expect_experts.extend([expert if mask is None else local]*(n//b))
        if mask is not None and mask[expert]: local += 1
    i = ids.to('cuda'); w = weights.to('cuda'); em = None if mask is None else mask.to('cuda')
    if c.get('public'):
        si, sw, se, valid, positions, buf = moe_sorting(
            i.to(torch.int64), w, e, c.get('h', 16), dtype, b, em)
    else:
        cap = max(0, m*k + e*b-k)
        si=torch.full((cap,), -777, dtype=torch.int32, device='cpu').to('cuda')
        sw=torch.full((cap,), -777., device='cpu').to('cuda')
        se=torch.full(((cap+b-1)//b,), -777, dtype=torch.int32, device='cpu').to('cuda')
        valid=torch.full((1,), -777, dtype=torch.int32, device='cpu').to('cuda')
        positions=torch.full((2*e,), -777, dtype=torch.int32, device='cpu').to('cuda')
        buf=None if c.get('no_buf') else torch.full((m,c.get('h',16)), 7., dtype=dtype).to('cuda')
        aiter.moe_sorting_fwd(i,w,si,sw,se,positions,valid,buf,e,b,em)
    torch.cuda.synchronize()
    n=valid.cpu().item()
    assert n==len(expect_ids),(n,len(expect_ids))
    assert positions.cpu().tolist()==counts+offsets, 'expert counts/offsets'
    assert se.cpu()[:n//b].tolist()==expect_experts, 'expert IDs'
    # Compare each expert's routes as a set of (encoded token/rank, weight).
    # Ordering within an expert is not part of the public contract.
    got_ids=si.cpu().tolist(); got_weights=sw.cpu().tolist()
    for expert in range(e):
        begin=offsets[expert]; end=offsets[expert+1] if expert+1<e else n
        actual=sorted(zip(got_ids[begin:end],got_weights[begin:end]))
        expected=sorted(zip(expect_ids[begin:end],expect_weights[begin:end]))
        assert actual==expected, ('routes/padding',expert,actual[:5],expected[:5])
    if buf is not None: assert torch.count_nonzero(buf.cpu())==0, 'moe_buf not cleared'
    assert torch.equal(i.cpu(),ids) and torch.equal(w.cpu(),weights),'input mutation'
    if em is not None: assert torch.equal(em.cpu(),mask),'mask mutation'
    return dict(**c,padded=n)


def sum_case(c,dtype):
    m,k,h=(c[x] for x in ('m','k','h'))
    gen=torch.Generator().manual_seed(946+k+h)
    cpu=(torch.randn((m,h,k),generator=gen).transpose(1,2) if c.get('strided')
         else torch.randn((m,k,h),generator=gen)).to(dtype)
    if k in (2,4,5,6,8):
        ref=torch.zeros((m,h),dtype=dtype)
        for rank in range(k): ref=(ref.float()+cpu[:,rank,:].float()).to(dtype)
    else: ref=cpu.float().sum(1).to(dtype)
    inp=cpu.to('cuda')
    out_cpu=torch.full((h,m) if c.get('strided') else (m,h),float('nan'),dtype=dtype)
    out=(out_cpu.t() if c.get('strided') else out_cpu).to('cuda')
    aiter.moe_sum(inp,out)
    torch.cuda.synchronize()
    got=out.cpu()
    torch.testing.assert_close(got,ref,rtol=1e-6 if dtype==torch.float32 else 0,atol=1e-6 if dtype==torch.float32 else 0)
    assert torch.equal(inp.cpu(),cpu),'input mutation'
    return dict(**c,max_abs=float((got.float()-ref.float()).abs().max()) if got.numel() else 0.)


def cases(args):
    if args.op=='sum':
        if args.suite=='route': return [dict(m=5,k=3 if args.route_path=='fallback' else 4,h=65)]
        if args.suite=='quick': return [dict(m=3,k=k,h=65) for k in (2,3)]
        return [dict(m=3,k=k,h=h) for k,h in ((1,1),(2,63),(3,65),(4,64),(5,127),(6,129),(8,1025),(7,17),(0,16))]+[dict(m=0,k=2,h=16),dict(m=3,k=4,h=0)]
    if args.suite=='route':
        return [dict(m=257,e=64,k=2,b=8,mask=True,no_buf=True)] if args.route_path=='mp' else [dict(m=4,e=8,k=2,b=8,h=2048)]
    base=[dict(m=5,e=8,k=2,b=4,public=True),dict(m=9,e=16,k=4,b=8,mask=True,invalid=True,no_buf=True)]
    if args.suite=='quick': return base
    return base+[
        dict(m=1,e=1,k=1,b=1),dict(m=7,e=8,k=3,b=3,invalid=True),
        dict(m=0,e=8,k=2,b=4),dict(m=3,e=8,k=2,b=8,all_invalid=True),
        dict(m=3,e=8,k=2,b=8,all_masked=True),
        dict(m=257,e=64,k=2,b=8,mask=True,invalid=True),
        dict(m=1025,e=16,k=2,b=32,no_buf=True)]


def config_cases(args, prefix):
    # Valid buffers are shared by rejection calls; no kernels run on rejection.
    inp=torch.ones((2,2,8),dtype=torch.float32).to('cuda')
    out=torch.empty((2,8),dtype=torch.float32,device='cuda')
    ids=torch.tensor([[0,1],[1,2]],dtype=torch.int32).to('cuda')
    weights=torch.ones((2,2),dtype=torch.float32).to('cuda')
    si=torch.empty(18,dtype=torch.int32,device='cuda')
    sw=torch.empty(18,dtype=torch.float32,device='cuda')
    se=torch.empty(5,dtype=torch.int32,device='cuda')
    pos=torch.empty(8,dtype=torch.int32,device='cuda')
    valid=torch.empty(1,dtype=torch.int32,device='cuda')
    def invoke():
        if args.op=='sum': aiter.moe_sum(inp,out)
        else: aiter.moe_sorting_fwd(ids,weights,si,sw,se,pos,valid,None,4,4,None)
    tests=[('bad_mode',{'DIE_MODE':'bad'},'must be auto')]
    if args.require_arch=='gfx946' and args.expect_xcds and args.expect_xcds>=2:
        tests += [(f'chunk_{v}',{'DIE_MODE':'linear','DIE_CHUNK':v},'DIE_CHUNK')
                  for v in ('0','-1','bad','4294967296')]
        tests += [('mask',{'DIE_MODE':'linear','DIE_MASK':'1'},'all dies')]
    else:
        tests += [('linear_unavailable',{'DIE_MODE':'linear'},'requires')]
    results=[]
    for name,values,message in tests:
        old={key:os.environ.get(prefix+'_'+key) for key in values}
        try:
            for key,value in values.items(): os.environ[prefix+'_'+key]=value
            try: invoke()
            except (RuntimeError,ValueError) as error:
                assert message in str(error),(message,str(error))
            else: raise AssertionError('configuration accepted: '+name)
        finally:
            for key,value in old.items():
                if value is None: os.environ.pop(prefix+'_'+key,None)
                else: os.environ[prefix+'_'+key]=value
        results.append(dict(rejected=name)); print('PASS rejection',name,flush=True)
    return results


def main():
    p=argparse.ArgumentParser(description=__doc__)
    p.add_argument('--op',choices=('sorting','sum'),required=True)
    p.add_argument('--suite',choices=('quick','full','route','config'),default='quick')
    p.add_argument('--dtype',choices=DTYPES,default='bf16')
    p.add_argument('--require-arch',default='gfx946')
    p.add_argument('--expect-xcds',type=int)
    p.add_argument('--die-mode',choices=('auto','off','linear'),default='auto')
    p.add_argument('--chunk',type=int,default=1)
    p.add_argument('--route-path',choices=('oneshot','mp','fallback'),default='oneshot')
    p.add_argument('--case',type=int,help='Run only this zero-based matrix entry')
    p.add_argument('--non-default-stream',action='store_true')
    p.add_argument('--strided',action='store_true',help='Exercise strided torch.sum fallback')
    p.add_argument('--json',type=Path)
    args=p.parse_args()
    torch.cuda.init()
    prop=torch.cuda.get_device_properties(torch.cuda.current_device())
    assert prop.gcnArchName.split(':')[0]==args.require_arch,prop
    topo=topology() if args.expect_xcds is not None else []
    if args.expect_xcds is not None:
        assert any(x['status']==0 and x['xcds']==args.expect_xcds for x in topo),topo
    os.environ.pop('GPU_CHIP',None)
    prefix='AITER_MOE_SORTING' if args.op=='sorting' else 'AITER_MOE_SUM'
    os.environ[prefix+'_DIE_MODE']=args.die_mode
    os.environ[prefix+'_DIE_CHUNK']=str(args.chunk)
    os.environ[prefix+'_LOG_LAUNCH']='1'
    info=dict(aiter=aiter.__file__,torch=torch.__version__,hip=torch.version.hip,
              arch=prop.gcnArchName,topology=topo,cases=[],
              test_sha256=hashlib.sha256(Path(__file__).read_bytes()).hexdigest())
    print('ENV',json.dumps({k:v for k,v in info.items() if k!='cases'}),flush=True)
    stream=torch.cuda.Stream() if args.non_default_stream else torch.cuda.current_stream()
    matrix=[] if args.suite=='config' else cases(args)
    if args.suite=='config':
        with torch.cuda.stream(stream): info['cases']=config_cases(args,prefix)
    if args.case is not None: matrix=[matrix[args.case]]
    if args.strided:
        assert args.op=='sum' and all(c['k'] not in (2,4,5,6,8) for c in matrix)
        matrix=[dict(c,strided=True) for c in matrix]
    for c in matrix:
        print('CASE',c,flush=True)
        with torch.cuda.stream(stream):
            result=(sorting_case if args.op=='sorting' else sum_case)(c,DTYPES[args.dtype])
        info['cases'].append(result)
        print('PASS',result,flush=True)
    name='module_cpp_api' if args.op=='sorting' else 'module_moe_utils'
    from aiter.jit.core import get_module
    module=get_module(name); path=Path(module.__file__)
    info['binary']=dict(path=str(path),sha256=hashlib.sha256(path.read_bytes()).hexdigest())
    info['passed']=len(info['cases'])
    if args.json:
        args.json.parent.mkdir(parents=True,exist_ok=True)
        args.json.write_text(json.dumps(info,indent=2),encoding='utf8')
    print('SUMMARY',json.dumps(dict(passed=info['passed'],binary=info['binary'])),flush=True)

if __name__=='__main__': main()
