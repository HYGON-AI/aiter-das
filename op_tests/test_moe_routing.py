# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Independent mathematical references and contract tests for MoE routing."""
import itertools
import pytest
import torch

TOKEN_COUNTS = [1,2,4,8,16,32,64,128,256,384,512,640,768,896,1024,1280,1536,1792,
                2048,4096,6192,8192,10240,12288,14336,16384,18432,20480,22528,24576,
                26624,28672,30720,32768,40960,49152,57344,65536,73728,81920,90112,
                98304,106496,114688,122880,131072]


def routing_cases():
    """516 unique configurations; 756 separate operator correctness records."""
    cases = []
    for m, sp in itertools.product(TOKEN_COUNTS, (1,8)):
        cases.append(dict(id=f'gather_m{m}_sp{sp}',family='gather',M=m,H=1536,Hout=1536,K=8,E=16,E_global=128,EP=8,SP=sp,dtype='bfloat16',mode='none',alignment=1))
    for m, eg, mode in itertools.product(TOKEN_COUNTS,(64,128),('int8','fp8_e4m3fn')):
        cases.append(dict(id=f'scatter_m{m}_e{eg}_{mode}',family='scatter',M=m,H=4096,Hout=4096,K=8,E=eg//8,E_global=eg,EP=8,SP=1,dtype='bfloat16',mode=mode,alignment=1))
    for m,k,e,h in itertools.product((10240,20480,40960,81920),(15,20,25,30),(800,1000,1200),(1024,1280,1536,2048,4096)):
        cases.append(dict(id=f'route_m{m}_k{k}_e{e}_h{h}',family='init_finalize',M=m,H=h,Hout=h,K=k,E=e,E_global=e,EP=1,SP=1,dtype='bfloat16',mode='none',alignment=1))
    assert len(cases)==516 and len({c['id'] for c in cases})==516
    return cases


def metadata_reference(ids, weights, E, expert_map=None, alignment=1, active=0, expert_capacity=0, capacity=None):
    """CPU oracle, deliberately independent of GPU scan/sort implementation."""
    assert active >= 0 and (not expert_capacity or (alignment == 1 and active == 0))
    cpu_ids=ids.cpu().to(torch.int64); cpu_w=weights.cpu().float()
    mapping=None if expert_map is None else expert_map.cpu().tolist()
    M,K=ids.shape
    groups=[[] for _ in range(E)]
    for f,g in enumerate(cpu_ids.flatten().tolist()):
        e=g if mapping is None else (mapping[g] if 0<=g<len(mapping) else -1)
        if 0<=e<E: groups[e].append(f)
    remaining=active if active else M*K
    kept=[]
    for group in groups:
        group=group[:expert_capacity] if expert_capacity else group[:remaining]
        if not expert_capacity: remaining-=len(group)
        kept.append(group)
    counts=torch.tensor([len(g) for g in kept],dtype=torch.int32)
    spans=[expert_capacity if expert_capacity else (len(g)+alignment-1)//alignment*alignment for g in kept]
    offsets=torch.tensor([sum(spans[:e]) for e in range(E)],dtype=torch.int32)
    T=capacity if capacity is not None else sum(spans)
    result={name:torch.full((T,),-1,dtype=torch.int32) for name in ('route_ids','token_ids','m_indices')}
    result.update(counts=counts,offsets=offsets,inv_perm=torch.full((M,K),-1,dtype=torch.int32),token_weights=torch.zeros(T,dtype=torch.float32),valid_rows=torch.tensor([int(counts.sum())],dtype=torch.int32),span_rows=torch.tensor([sum(spans)],dtype=torch.int32),status=torch.zeros(1,dtype=torch.int32))
    for e,group in enumerate(kept):
        for j,f in enumerate(group):
            r=int(offsets[e])+j; t,k=divmod(f,K)
            result['route_ids'][r]=f; result['token_ids'][r]=t; result['m_indices'][r]=e
            result['inv_perm'][t,k]=r; result['token_weights'][r]=cpu_w[t,k]
    return result


def quant_reference(x, smooth=None, mode='int8'):
    def ftz(t):
        t=t.float()
        return torch.where(t.abs()<torch.finfo(torch.float32).tiny,torch.copysign(torch.zeros_like(t),t),t)
    z=ftz(ftz(x) if smooth is None else ftz(x)*ftz(smooth))
    maximum=z.abs().amax(-1,keepdim=True)
    qmax=127.0 if mode=='int8' else 448.0
    # FP64 division followed by FP32 rounding independently implements RN;
    # torch's FP32 division by a scalar may instead multiply by its reciprocal.
    scale=torch.where(maximum==0,torch.ones_like(maximum),(maximum.double()/qmax).float().clamp_min(torch.finfo(torch.float32).tiny))
    values=(z.double()/scale.double()).float()
    quant=(values.round().clamp(-127,127).to(torch.int8) if mode=='int8'
           else values.clamp(-448,448).to(torch.float8_e4m3fn))
    return quant,scale


def gather_reference(expert_output,weights,inv_perm,m_indices,bias=None,residual=None,res_scale=1.,residual_start=0,residual_end=-1,x2=None,use_fp64=False):
    M,K=inv_perm.shape; H=expert_output.shape[1]
    dtype=torch.float64 if use_fp64 else torch.float32
    out=torch.zeros((M,H),device=expert_output.device,dtype=dtype)
    end=M if residual_end==-1 else residual_end
    if residual is not None:
        out[residual_start:end]=residual.to(dtype)*res_scale
    if x2 is not None: out+=x2.to(dtype)
    for k in range(K):
        rows=inv_perm[:,k].long(); valid=(rows>=0)&(rows<expert_output.shape[0])
        tokens=valid.nonzero().flatten(); rows=rows[valid]
        term=expert_output[rows].to(dtype)
        if bias is not None: term=term+bias[m_indices[rows].long()].to(dtype)
        # Separate multiply and add: no fused multiply-add in the reference.
        out[tokens]=out[tokens]+term*weights[valid,k,None].to(dtype)
    return out


def test_reference_direction():
    ids=torch.tensor([[2,0],[1,2]],dtype=torch.int64)
    ref=metadata_reference(ids,torch.tensor([[.1,.2],[.3,.4]]),3)
    assert ref['route_ids'].tolist()==[1,2,0,3]
    assert ref['inv_perm'].tolist()==[[2,0],[1,3]]
    assert ref['counts'].tolist()==[1,1,2]
    assert metadata_reference(ids,torch.ones(2,2),3,active=3)['counts'].tolist()==[1,1,1]
    assert metadata_reference(ids,torch.ones(2,2),3,expert_capacity=1)['route_ids'].tolist()==[1,2,0]


def api():
    from aiter.ops import moe_routing
    return moe_routing


def check_metadata(buffers, reference):
    for name, expected in reference.items():
        actual=getattr(buffers,name).cpu()
        assert torch.equal(actual,expected), f'{name}: {actual} != {expected}'


@pytest.mark.parametrize('dtype',[torch.float16,torch.bfloat16,torch.float32])
@pytest.mark.parametrize('mode',['none','int8','fp8_e4m3fn'])
def test_routing_smoke(dtype,mode):
    r=api();M,H,K,E=7,17,30,1200
    ids=(torch.arange(M*K,device='cuda').reshape(M,K)%5+1202).long()
    ids.flatten()[::11]=-1;ids.flatten()[1::13]=2**40
    mapping=torch.full((1210,),-1,device='cuda',dtype=torch.int32)
    mapping[1202:1207]=torch.tensor([0,1199,1024,-1,1201],device='cuda',dtype=torch.int32)
    weights=torch.randn(M,K,device='cuda');x=torch.randn(M,H,device='cuda',dtype=dtype)
    b=r.allocate_moe_routing(ids,E,alignment=16)
    ref=metadata_reference(ids,weights,E,mapping,16,capacity=b.route_ids.numel())
    b.prepare(ids,weights,mapping);check_metadata(b,ref)
    dt=dtype if mode=='none' else (torch.int8 if mode=='int8' else torch.float8_e4m3fn)
    out=torch.empty(b.route_ids.numel(),H,device='cuda',dtype=dt)
    scale=None if mode=='none' else torch.empty(out.shape[0],1,device='cuda')
    smooth=None if mode=='none' else torch.rand(E,H,device='cuda')*2
    r.moe_routing_scatter_out(out,scale,x,b.token_ids,b.m_indices,smooth,mode)
    valid=b.token_ids>=0;tokens=b.token_ids[valid].long();experts=b.m_indices[valid].long()
    if mode=='none': assert torch.equal(out[valid],x[tokens])
    else:
        q,s=quant_reference(x[tokens],smooth[experts],mode)
        assert torch.equal(out.view(torch.uint8)[valid],q.view(torch.uint8))
        assert torch.equal(scale[valid],s)
        assert torch.all(scale[~valid]==1)
    assert torch.count_nonzero(out.view(torch.uint8)[~valid])==0
    # Different Hout proves the two data stages do not bind feature widths.
    Hout=15;mid=torch.randn(out.shape[0],Hout,device='cuda',dtype=dtype)
    bias=torch.randn(E,Hout,device='cuda');res=torch.randn(1,Hout,device='cuda',dtype=dtype)
    x2=torch.randn(M,Hout,device='cuda',dtype=dtype);y=torch.empty_like(x2)
    r.moe_routing_gather_out(y,mid,weights,b.inv_perm,b.m_indices,bias,res,-.5,2,6,x2)
    expected=gather_reference(mid,weights,b.inv_perm,b.m_indices,bias,res,-.5,2,6,x2).to(dtype)
    torch.testing.assert_close(y,expected,rtol=0,atol=0)
    before=y.clone();r.moe_routing_gather_out(y,mid,weights,b.inv_perm,b.m_indices,bias,res,-.5,2,6,x2)
    assert torch.equal(y,before)
    check_metadata(b,ref)
    cumulative=torch.empty_like(b.counts);r.moe_routing_cumsum_out(cumulative,b.counts)
    assert torch.equal(cumulative,torch.cumsum(b.counts,0,dtype=torch.int32))


@pytest.mark.parametrize('alignment,capacity',[(1,0),(16,0),(64,0),(128,0),(1,1),(1,3),(1,100)])
def test_active_drop_and_reuse(alignment,capacity):
    r=api();ids=torch.tensor([[2,0,2],[1,-1,0],[2,2,2]],device='cuda',dtype=torch.int32)
    weights=torch.arange(9,device='cuda',dtype=torch.float32).reshape(3,3)/7
    b=r.allocate_moe_routing(ids,4,alignment,capacity);active=torch.zeros(1,device='cuda',dtype=torch.int64)
    for n in ([0] if capacity else [0,1,7,8,20]):
        active.fill_(n);b.prepare(ids,weights,active_num=active)
        check_metadata(b,metadata_reference(ids,weights,4,alignment=alignment,active=n,expert_capacity=capacity,capacity=b.route_ids.numel()))
        r.check_moe_routing_status(b.status)
    active.fill_(-1);b.prepare(ids,weights,active_num=active)
    with pytest.raises(ValueError,match='nonnegative'):r.check_moe_routing_status(b.status)
    assert torch.all(b.inv_perm==-1) and int(b.valid_rows)==0
    if capacity:
        active.fill_(1);b.prepare(ids,weights,active_num=active)
        with pytest.raises(ValueError,match='DropPad'):r.check_moe_routing_status(b.status)
    active.zero_();ids.fill_(-1);b.prepare(ids,weights,active_num=active)
    check_metadata(b,metadata_reference(ids,weights,4,alignment=alignment,expert_capacity=capacity,capacity=b.route_ids.numel()))


@pytest.mark.parametrize('mode',['none','int8','fp8_e4m3fn'])
def test_changing_graph_and_stream(mode):
    r=api();M,H,K,E=31,129,8,16
    ids=torch.randint(E+4,(M,K),device='cuda',dtype=torch.int64)
    weights=torch.randn(M,K,device='cuda');x=torch.randn(M,H,device='cuda',dtype=torch.bfloat16)
    mapping=torch.arange(E+4,device='cuda',dtype=torch.int32);mapping[E:]=-1
    active=torch.zeros(1,device='cuda',dtype=torch.int64);b=r.allocate_moe_routing(ids,E,16)
    out_dtype=x.dtype if mode=='none' else torch.int8 if mode=='int8' else torch.float8_e4m3fn
    expanded=torch.empty(b.route_ids.numel(),H,device='cuda',dtype=out_dtype);y=torch.empty_like(x)
    scale=None if mode=='none' else torch.empty(expanded.shape[0],1,device='cuda')
    smooth=None if mode=='none' else torch.rand(E,H,device='cuda')+.25
    expert=expanded if mode=='none' else torch.randn(expanded.shape,device='cuda',dtype=x.dtype)
    def run():
        r.moe_init_routing_out(expanded,scale,x,ids,weights,b,mapping,smooth,mode,active_num=active)
        r.moe_finalize_routing_out(y,expert,weights,b)
    stream=torch.cuda.Stream();stream.wait_stream(torch.cuda.current_stream())
    with torch.cuda.stream(stream):run()
    torch.cuda.current_stream().wait_stream(stream)
    graph=torch.cuda.CUDAGraph()
    with torch.cuda.graph(graph):run()
    lengths=[]
    for i in range(3):
        x.add_(.5);weights.mul_(-.7);ids.copy_(torch.randint(E+4,ids.shape,device='cuda'))
        mapping.copy_(torch.arange(E+4,device='cuda',dtype=torch.int32));mapping[(i+1)::3]=-1
        active.fill_(1 if i==1 else 0)
        graph.replay();torch.cuda.synchronize()
        ref=metadata_reference(ids,weights,E,mapping,16,active=int(active),capacity=b.route_ids.numel())
        check_metadata(b,ref);lengths.append(int(b.valid_rows))
        valid=b.token_ids>=0;tokens=b.token_ids[valid].long()
        if mode=='none':assert torch.equal(expanded[valid],x[tokens])
        else:
            q,s=quant_reference(x[tokens],smooth[b.m_indices[valid].long()],mode)
            assert torch.equal(expanded.view(torch.uint8)[valid],q.view(torch.uint8)) and torch.equal(scale[valid],s)
        expected=gather_reference(expert,weights,b.inv_perm,b.m_indices).to(y.dtype)
        torch.testing.assert_close(y,expected,rtol=0,atol=0)
    assert lengths[1]==1 and lengths[0]>1 and lengths[2]>1


def metadata_reference_vectorized(ids,weights,E,expert_map=None,alignment=1,active=0,expert_capacity=0,capacity=None):
    """CPU stable expert sort oracle, without composite radix keys or GPU scan."""
    ids=ids.cpu().long();weights=weights.cpu().float();flat=ids.flatten();M,K=ids.shape
    if expert_map is None: mapped=flat.clone()
    else:
        mapping=expert_map.cpu().long();mapped=torch.full_like(flat,-1)
        mask=(flat>=0)&(flat<mapping.numel());mapped[mask]=mapping[flat[mask]]
    valid=(mapped>=0)&(mapped<E);f=valid.nonzero().flatten();e=mapped[valid]
    order=torch.argsort(e,stable=True);f=f[order];e=e[order]
    raw_counts=torch.bincount(e,minlength=E)
    if expert_capacity:
        start=torch.cumsum(raw_counts,0)-raw_counts
        rank=torch.arange(e.numel())-start[e]
        keep=rank<expert_capacity;f=f[keep];e=e[keep]
    elif active: f=f[:active];e=e[:active]
    counts=torch.bincount(e,minlength=E)
    spans=torch.full_like(counts,expert_capacity) if expert_capacity else (counts+alignment-1)//alignment*alignment
    offsets=torch.cumsum(spans,0)-spans
    starts=torch.cumsum(counts,0)-counts
    rows=offsets[e]+torch.arange(e.numel())-starts[e]
    T=capacity if capacity is not None else int(spans.sum())
    result={name:torch.full((T,),-1,dtype=torch.int32) for name in ('route_ids','token_ids','m_indices')}
    result.update(counts=counts.int(),offsets=offsets.int(),inv_perm=torch.full((M,K),-1,dtype=torch.int32),token_weights=torch.zeros(T),valid_rows=torch.tensor([f.numel()],dtype=torch.int32),span_rows=torch.tensor([int(spans.sum())],dtype=torch.int32),status=torch.zeros(1,dtype=torch.int32))
    result['route_ids'][rows]=f.int();result['token_ids'][rows]=(f//K).int();result['m_indices'][rows]=e.int()
    result['inv_perm'].view(-1)[f]=rows.int();result['token_weights'][rows]=weights.flatten()[f]
    return result


def test_independent_metadata_oracles():
    ids=torch.tensor([[4,0,1],[4,-1,1],[2,3,2]])
    weights=torch.arange(9).reshape(3,3).float();mapping=torch.tensor([2,-1,0,1,0])
    for a,active,cap in [(1,0,0),(16,4,0),(1,0,2)]:
        left=metadata_reference(ids,weights,3,mapping,a,active,cap)
        right=metadata_reference_vectorized(ids,weights,3,mapping,a,active,cap)
        for key in left:assert torch.equal(left[key],right[key])


@pytest.mark.parametrize('K',range(1,31))
@pytest.mark.parametrize('id_dtype',[torch.int32,torch.int64])
def test_all_topk(K,id_dtype):
    r=api();ids=(torch.arange(7*K,device='cuda')%3).reshape(7,K).to(id_dtype)
    ids.flatten()[::7]=-1;w=torch.randn(7,K,device='cuda');b=r.allocate_moe_routing(ids,8)
    b.prepare(ids,w);check_metadata(b,metadata_reference(ids,w,8,capacity=b.route_ids.numel()))


@pytest.mark.parametrize('E',[1,8,16,64,800,1000,1024,1025,1200])
@pytest.mark.parametrize('alignment',[1,16,64,128])
def test_expert_alignment_boundaries(E,alignment):
    r=api();ids=torch.randint(E,(31,17),device='cuda',dtype=torch.int32);ids[0]=E-1
    w=torch.randn(ids.shape,device='cuda');b=r.allocate_moe_routing(ids,E,alignment)
    b.prepare(ids,w);check_metadata(b,metadata_reference(ids,w,E,alignment=alignment,capacity=b.route_ids.numel()))


@pytest.mark.parametrize('M',[0,1,2,7,31,128,129])
def test_token_empty_skew(M):
    r=api();ids=torch.zeros((M,9),device='cuda',dtype=torch.int64);w=torch.ones(M,9,device='cuda')
    b=r.allocate_moe_routing(ids,8,16);x=torch.randn(M,7,device='cuda');out=torch.empty(b.route_ids.numel(),7,device='cuda')
    for empty in [False,True]:
        if empty:ids.fill_(-1)
        r.moe_init_routing_out(out,None,x,ids,w,b)
        ref=metadata_reference(ids,w,8,alignment=16,capacity=b.route_ids.numel());check_metadata(b,ref)
        y=torch.empty_like(x);res=torch.ones(1,7,device='cuda')
        r.moe_finalize_routing_out(y,out,w,b,residual=res,res_scale=.5)
        expected=gather_reference(out,w,b.inv_perm,b.m_indices,residual=res,res_scale=.5)
        assert torch.equal(y,expected)


@pytest.mark.parametrize('H',[1,7,15,16,17,127,128,129,1536,4096,7168])
@pytest.mark.parametrize('dtype',[torch.float16,torch.bfloat16,torch.float32])
@pytest.mark.parametrize('mode',['none','int8','fp8_e4m3fn'])
def test_tails_offsets_quant(H,dtype,mode):
    r=api();M,K,E=7,4,8
    ids=torch.randint(E,(M,K),device='cuda',dtype=torch.int64);w=torch.rand(M,K,device='cuda')
    b=r.allocate_moe_routing(ids,E,16);b.prepare(ids,w)
    storage=torch.full((M*H+2,),42,device='cuda',dtype=dtype);x=storage[1:-1].view(M,H);x.copy_(torch.randn_like(x));x[0].zero_()
    dt=dtype if mode=='none' else (torch.int8 if mode=='int8' else torch.float8_e4m3fn)
    backing=torch.full((b.route_ids.numel()*H+2,),42,device='cuda',dtype=dt)
    original=backing.view(torch.uint8).clone();out=backing[1:-1].view(-1,H)
    scale=None if mode=='none' else torch.empty(out.shape[0],1,device='cuda')
    smooth=None if mode=='none' else torch.rand(E,H,device='cuda')*3
    if smooth is not None:smooth[0].zero_()
    r.moe_routing_scatter_out(out,scale,x,b.token_ids,b.m_indices,smooth,mode)
    valid=b.token_ids>=0;tokens=b.token_ids[valid].long();experts=b.m_indices[valid].long()
    if mode=='none':assert torch.equal(out[valid],x[tokens])
    else:
        q,s=quant_reference(x[tokens],smooth[experts],mode)
        assert torch.equal(out.view(torch.uint8)[valid],q.view(torch.uint8))
        assert torch.equal(scale[valid],s) and torch.all(scale[~valid]==1)
    assert torch.count_nonzero(out.view(torch.uint8)[~valid])==0
    n=backing.element_size();assert torch.equal(backing.view(torch.uint8)[:n],original[:n]);assert torch.equal(backing.view(torch.uint8)[-n:],original[-n:])
    assert storage[0]==42 and storage[-1]==42
    if mode=='none':
        dst=torch.full((M*H+2,),42,device='cuda',dtype=dtype);y=dst[1:-1].view(M,H)
        r.moe_finalize_routing_out(y,out,w,b)
        assert torch.equal(y,gather_reference(out,w,b.inv_perm,b.m_indices).to(dtype))
        assert dst[0]==42 and dst[-1]==42


@pytest.mark.parametrize('mode',['int8','fp8_e4m3fn'])
def test_quant_rounding_and_tiny(mode):
    r=api();limit=127. if mode=='int8' else 448.
    values=[0.,-0.,.5,1.5,2.5,-.5,-1.5,-2.5,limit,-limit,1e-38,1e-40]
    x=torch.tensor([values,[v*1e-30 for v in values],[0.]*len(values)],device='cuda')
    ids=torch.zeros(3,1,device='cuda',dtype=torch.int32);w=torch.ones(3,1,device='cuda');b=r.allocate_moe_routing(ids,1);b.prepare(ids,w)
    q=torch.empty_like(x,dtype=torch.int8 if mode=='int8' else torch.float8_e4m3fn);s=torch.empty(3,1,device='cuda')
    r.moe_routing_scatter_out(q,s,x,b.token_ids,b.m_indices,mode=mode)
    expected,scale=quant_reference(x,mode=mode)
    assert torch.equal(q.view(torch.uint8),expected.view(torch.uint8));assert torch.equal(s,scale)


@pytest.mark.parametrize('res_scale',[0.,.5,-1.])
@pytest.mark.parametrize('M',[0,1,7,9,31])
def test_sp_bias_residual(M,res_scale):
    r=api();H,K,E=15,9,8;ids=torch.randint(E,(M,K),device='cuda',dtype=torch.int32);w=torch.randn(M,K,device='cuda');w[:,0]=0
    b=r.allocate_moe_routing(ids,E);b.prepare(ids,w)
    mid=torch.randn(b.route_ids.numel(),H,device='cuda');bias=torch.randn(E,H,device='cuda');x2=torch.randn(M,H,device='cuda');out=torch.empty_like(x2)
    for sp in [1,8]:
        for rank in range(sp):
            chunk=(M+sp-1)//sp;start=min(M,rank*chunk);end=min(M,start+chunk)
            for broadcast in [False,True]:
                res=torch.randn(1 if broadcast else end-start,H,device='cuda')
                r.moe_finalize_routing_out(out,mid,w,b,bias,res,res_scale,start,end,x2)
                expected=gather_reference(mid,w,b.inv_perm,b.m_indices,bias,res,res_scale,start,end,x2)
                assert torch.equal(out,expected)
    mid.fill_(float('inf'));r.moe_finalize_routing_out(out,mid,w,b)
    torch.testing.assert_close(out,gather_reference(mid,w,b.inv_perm,b.m_indices),rtol=0,atol=0,equal_nan=True)


def test_metadata_guards_and_fake():
    r=api();ids=torch.zeros(2,4,device='cuda',dtype=torch.int32);w=torch.ones(2,4,device='cuda');b=r.allocate_moe_routing(ids,8)
    for bad in [0,31]:
        with pytest.raises((ValueError,RuntimeError)):r.allocate_moe_routing(torch.empty(2,bad,device='cuda',dtype=torch.int32),8)
    for bad in [0,1201]:
        with pytest.raises((ValueError,RuntimeError)):r.allocate_moe_routing(ids,bad)
    with pytest.raises((ValueError,RuntimeError)):r.allocate_moe_routing(ids,8,3)
    with pytest.raises((ValueError,RuntimeError)):r.allocate_moe_routing(ids,8,16,3)
    args=[ids,w,None,b.counts,b.offsets,b.route_ids,b.inv_perm,b.token_ids,b.token_weights,b.m_indices,b.valid_rows,b.span_rows,b.status,b.workspace,8,1,None,0]
    for index,bad in [(1,w.double()),(1,w.cpu()),(4,b.counts),(5,b.route_ids[:-1]),(13,b.workspace[:1])]:
        changed=args.copy();changed[index]=bad
        with pytest.raises((ValueError,RuntimeError,TypeError)):r.moe_routing_prepare_out(*changed)
    x=torch.randn(2,7,device='cuda');out=torch.empty(8,7,device='cuda')
    with pytest.raises((ValueError,RuntimeError)):r.moe_routing_scatter_out(out,None,x.T,b.token_ids,b.m_indices)
    one=torch.zeros(2,1,device='cuda',dtype=torch.int32);oneb=r.allocate_moe_routing(one,1);oneb.prepare(one,torch.ones(2,1,device='cuda'))
    with pytest.raises((ValueError,RuntimeError)):r.moe_routing_scatter_out(x,None,x,oneb.token_ids,oneb.m_indices)
    from torch._subclasses.fake_tensor import FakeTensorMode
    with FakeTensorMode() as fake:
        fargs=[fake.from_tensor(t) if isinstance(t,torch.Tensor) else t for t in args]
        r.moe_routing_prepare_out(*fargs)
        r.moe_routing_scatter_out(fake.from_tensor(out),None,fake.from_tensor(x),fargs[7],fargs[9])
    meta=[torch.empty_strided(t.shape,t.stride(),device='meta',dtype=t.dtype) if isinstance(t,torch.Tensor) else t for t in args]
    r.moe_routing_prepare_out(*meta)


def test_fullgraph_compile_mutation():
    r=api();M,H,K,E=7,17,9,8
    ids=torch.randint(E,(M,K),device='cuda',dtype=torch.int32);w=torch.randn(M,K,device='cuda');x=torch.randn(M,H,device='cuda')
    mapping=torch.arange(E,device='cuda',dtype=torch.int32);active=torch.zeros(1,device='cuda',dtype=torch.int64)
    b=r.allocate_moe_routing(ids,E);expanded=torch.empty(b.route_ids.numel(),H,device='cuda');y=torch.empty_like(x)
    def fn(x,ids,w,mapping,active):
        r.moe_init_routing_out(expanded,None,x,ids,w,b,mapping,active_num=active)
        r.moe_finalize_routing_out(y,expanded,w,b)
        return y
    fn(x,ids,w,mapping,active)
    compiled=torch.compile(fn,fullgraph=True)
    addresses=[t.data_ptr() for t in [expanded,y,b.counts,b.inv_perm]]
    for i in range(3):
        ids.copy_(torch.randint(E,(M,K),device='cuda',dtype=torch.int32));x.add_(.25);w.mul_(-.5);mapping[i]=-1;active.fill_(0 if i==0 else i)
        result=compiled(x,ids,w,mapping,active)
        torch.cuda.synchronize();assert result.data_ptr()==y.data_ptr()
        check_metadata(b,metadata_reference(ids,w,E,mapping,active=int(active),capacity=b.route_ids.numel()))
        expected=gather_reference(expanded,w,b.inv_perm,b.m_indices)
        assert torch.equal(result,expected)
    assert addresses==[t.data_ptr() for t in [expanded,y,b.counts,b.inv_perm]]
