"""QK distributed RMS statistics + NeoX RoPE; independent FP32 reference."""
from datetime import timedelta
import os
import torch
import torch.distributed as dist
from aiter.dist.device_communicators.custom_all_reduce import CustomAllreduce
from aiter.dist import parallel_state as ps


def rotate(x, cache, positions, head, rotary):
    x = x.reshape(x.shape[0], -1, head)
    out = x.clone()
    a, b = x[..., :rotary//2], x[..., rotary//2:rotary]
    c, s = cache[positions, :rotary//2].unsqueeze(1), cache[positions, rotary//2:].unsqueeze(1)
    out[..., :rotary//2] = a*c-b*s
    out[..., rotary//2:rotary] = b*c+a*s
    return out.flatten(1)


def main():
    rank, local, world = [int(os.environ[k]) for k in ('RANK','LOCAL_RANK','WORLD_SIZE')]
    torch.cuda.set_device(local)
    device=torch.device('cuda',local)
    dist.init_process_group('gloo',timeout=timedelta(seconds=180))
    count=0
    for register in (False,True):
        ca=CustomAllreduce(dist.group.WORLD,device,max_size=32*1024*1024,enable_register_for_capturing=register)
        assert not ca.disabled
        try:
            for dtype in (torch.float32,torch.float16,torch.bfloat16):
                tol={torch.float32:2e-5,torch.float16:.005,torch.bfloat16:.04}[dtype]
                for tokens,head,rotary in ((4,64,64),(4,128,96),(129,128,64)):
                    x=torch.empty((tokens,1024),dtype=dtype,device=device)
                    qw=torch.linspace(.5,1.5,512,device=device).to(dtype)
                    kw=torch.linspace(.5,1.5,256,device=device).to(dtype)
                    angles=torch.arange(32*rotary//2,device=device).reshape(32,rotary//2).float()/37
                    cache=torch.cat((angles.cos(),angles.sin()),-1).to(dtype)
                    pos=torch.empty(tokens,dtype=torch.int64,device=device)
                    base=((torch.arange(x.numel(),device=device).reshape(x.shape)%31).float()-15)/32
                    def fill(i):
                        inputs=[(base+r/16+(i%5)/32).to(dtype) for r in range(world)]
                        x.copy_(inputs[rank]);pos.copy_((torch.arange(tokens,device=device)+i)%32)
                        q,k,v=inputs[rank].float().split((512,256,256),-1)
                        qvar=sum(t[:,:512].float().square().mean(-1,keepdim=True) for t in inputs)/world
                        kvar=sum(t[:,512:768].float().square().mean(-1,keepdim=True) for t in inputs)/world
                        q=(q*torch.rsqrt(qvar+1e-6)*qw.float()).to(dtype).float()
                        k=(k*torch.rsqrt(kvar+1e-6)*kw.float()).to(dtype).float()
                        return rotate(q,cache.float(),pos,head,rotary),rotate(k,cache.float(),pos,head,rotary),v
                    def invoke():return ca.custom_fused_qknorm_ar_rope(x,qw,kw,cache,pos,head,rotary,1e-6)
                    def check(outputs,expected):
                        for a,b in zip(outputs,expected):
                            assert torch.isfinite(a).all()
                            torch.testing.assert_close(a.float(),b,rtol=tol,atol=tol)
                    ref=fill(0);check(invoke(),ref)
                    with ca.capture():check(invoke(),ref)
                    graph=torch.cuda.CUDAGraph()
                    with ca.capture():
                        with torch.cuda.graph(graph):out=invoke()
                    for i in range(100):
                        ref=fill(i);graph.replay();check(out,ref)
                    del graph
                    for bad_head,bad_rotary in ((96,64),(128,40)):
                        try:ca.fused_qknorm_ar_rope(x,qw,kw,cache,pos,bad_head,bad_rotary,1e-6)
                        except (ValueError,RuntimeError):pass
                        else:raise AssertionError('invalid RoPE layout accepted')
                    count+=1
            torch.cuda.synchronize();dist.barrier()
        finally:ca.close()
    # Fake/fullgraph does not need a live process group lookup.
    for dtype in (torch.float16,torch.bfloat16):
        x=torch.empty((4,1024),dtype=dtype,device='meta')
        qw=torch.empty(512,dtype=dtype,device='meta');kw=torch.empty(256,dtype=dtype,device='meta')
        cache=torch.empty((32,64),dtype=dtype,device='meta');pos=torch.empty(4,dtype=torch.int64,device='meta')
        torch._dynamo.reset()
        fn=torch.compile(ps.fused_qknorm_allreduce_rope_,backend='eager',fullgraph=True)
        out=fn(x,qw,kw,cache,pos,128,64,1e-6,'meta_only')
        assert [t.shape for t in out]==[(4,512),(4,256),(4,256)]
    print('QK_ROPE_PASS',rank,world,'cases',count,'replays',100,flush=True)
    dist.destroy_process_group()

if __name__=='__main__':main()
