// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
// Fixed-capacity, deterministic local MoE routing. No host route readback.
#include "moe_routing.h"
#include "moe_routing_common.cuh"
#include "dispatch_utils.h"
#include <ATen/hip/HIPContext.h>
#include <ATen/hip/impl/HIPGuardImplMasqueradingAsCUDA.h>
#include <hipcub/hipcub.hpp>
#include <c10/util/Float8_e4m3fn.h>
#include <cfloat>

namespace aiter {
namespace {
constexpr int block=256;
constexpr int key_bits=43; // 11 expert bits + 32 token-major route bits.
size_t align_bytes(size_t n) { return (n+255)&~size_t(255); }
size_t scratch_bytes(int n) {
  size_t bytes=0;
  if(n) TORCH_CHECK(hipcub::DeviceRadixSort::SortKeys(nullptr,bytes,
      static_cast<uint64_t*>(nullptr),static_cast<uint64_t*>(nullptr),n,0,key_bits)==hipSuccess,"routing sort query failed");
  return bytes;
}
size_t workspace_bytes(int n) { return 2*align_bytes(size_t(n)*8)+align_bytes(routing::max_experts*4)+scratch_bytes(n); }
void clear(const torch::Tensor& t,int value,hipStream_t stream) {
  if(t.numel()) TORCH_CHECK(hipMemsetAsync(t.data_ptr(),value,t.nbytes(),stream)==hipSuccess,"routing initialization failed");
}
void launched() { TORCH_CHECK(hipGetLastError()==hipSuccess,"routing kernel launch failed"); }

__global__ void make_keys(const void* ids,const int32_t* map,uint64_t* keys,
                          int32_t* counts,int n,routing::RouteInfo info) {
  int64_t f=int64_t(blockIdx.x)*blockDim.x+threadIdx.x;
  if(f>=n) return;
  int e=info.local(ids,f,map);
  keys[f]=e<0 ? UINT64_MAX : (uint64_t(e)<<32)|uint32_t(f);
  if(e>=0) atomicAdd(counts+e,1);
}

__global__ void make_layout(int32_t* counts,int32_t* offsets,int32_t* raw_starts,
    int32_t* valid_rows,int32_t* span_rows,int32_t* status,int E,int alignment,
    const int64_t* active,int capacity) {
  using Scan=hipcub::BlockScan<int,block>;
  using Reduce=hipcub::BlockReduce<int,block>;
  __shared__ union { typename Scan::TempStorage scan; typename Reduce::TempStorage reduce; } temp;
  __shared__ int error;
  int tid=threadIdx.x;
  int64_t limit=active ? *active : 0;
  if(tid==0) { error=limit<0 ? 1 : (capacity>0 && limit!=0 ? 2 : 0); *status=error; }
  int values[8],prefix[8];
  #pragma unroll
  for(int i=0;i<8;++i) { int e=tid*8+i; values[i]=e<E ? counts[e] : 0; }
  Scan(temp.scan).ExclusiveSum(values,prefix);
  __syncthreads();
  int stored[8]; int sum=0;
  #pragma unroll
  for(int i=0;i<8;++i) {
    int e=tid*8+i;
    int keep=values[i];
    if(error) keep=0;
    else if(capacity) keep=min(keep,capacity);
    else if(limit>0) keep=int(min(int64_t(keep),max(int64_t(0),limit-prefix[i])));
    if(e<E) { raw_starts[e]=prefix[i]; counts[e]=keep; }
    sum+=keep;
    stored[i]=e<E && !error ? (capacity ? capacity : (keep+alignment-1)&~(alignment-1)) : 0;
  }
  int total=Reduce(temp.reduce).Sum(sum);
  if(tid==0) *valid_rows=total;
  __syncthreads();
  int span=0;
  Scan(temp.scan).ExclusiveSum(stored,prefix,span);
  #pragma unroll
  for(int i=0;i<8;++i) { int e=tid*8+i; if(e<E) offsets[e]=prefix[i]; }
  if(tid==0) *span_rows=span;
}

__global__ void emit_routes(const uint64_t* keys,const float* weights,
    const int32_t* raw_starts,const int32_t* counts,const int32_t* offsets,
    int32_t* routes,int32_t* inv,int32_t* tokens,float* row_weights,int32_t* experts,int n,int K,int E) {
  int64_t s=int64_t(blockIdx.x)*blockDim.x+threadIdx.x;
  if(s>=n) return;
  uint64_t key=keys[s]; int e=int(key>>32);
  if(e<0 || e>=E) return;
  int rank=s-raw_starts[e];
  if(rank>=counts[e]) return;
  int f=int(uint32_t(key)),r=offsets[e]+rank;
  routes[r]=f; inv[f]=r; tokens[r]=f/K; row_weights[r]=weights[f]; experts[r]=e;
}

__device__ float ftz(float x) { return fabsf(x)<FLT_MIN ? copysignf(0.0f,x) : x; }
template<typename T>
__device__ float smoothed(const T* input,const float* smooth,int64_t t,int e,int H,int64_t j) {
  float x=ftz(float(input[t*H+j]));
  return ftz(x*(smooth ? ftz(smooth[int64_t(e)*H+j]) : 1.0f));
}
template<typename T,int Mode>
__global__ void scatter_rows(const T* input,void* out,float* scales,
    const int32_t* tokens,const int32_t* experts,const float* smooth,int M,int H,int E,int Tcap) {
  int r=blockIdx.x;
  if(r>=Tcap) return;
  int t=tokens[r],e=experts[r];
  bool valid=t>=0 && t<M && e>=0 && (!smooth || e<E);
  int64_t dst=int64_t(r)*H;
  // Padding never participates in the reduction. Fill full aligned vectors
  // directly; retain scalar stores for arbitrary widths/storage offsets.
  if(!valid) {
    constexpr int element_bytes=Mode==0 ? sizeof(T) : 1;
    int64_t bytes=int64_t(H)*element_bytes;
    auto row=static_cast<uint8_t*>(out)+dst*element_bytes;
    if(bytes%16==0 && reinterpret_cast<uintptr_t>(row)%16==0) {
      for(int64_t j=threadIdx.x;j<bytes/16;j+=blockDim.x)
        reinterpret_cast<int4*>(row)[j]=int4{0,0,0,0};
    } else {
      if constexpr(Mode==0) {
        for(int64_t j=threadIdx.x;j<H;j+=blockDim.x) static_cast<T*>(out)[dst+j]=T(0);
      } else {
        for(int64_t j=threadIdx.x;j<H;j+=blockDim.x) row[j]=0;
      }
    }
    if constexpr(Mode!=0) { if(threadIdx.x==0) scales[r]=1.0f; }
    return;
  }
  if constexpr(Mode==0) {
    auto src=input+int64_t(t)*H;
    auto target=static_cast<T*>(out)+dst;
    int64_t bytes=int64_t(H)*sizeof(T);
    if(bytes%16==0 && reinterpret_cast<uintptr_t>(src)%16==0 && reinterpret_cast<uintptr_t>(target)%16==0) {
      for(int64_t j=threadIdx.x;j<bytes/16;j+=blockDim.x)
        reinterpret_cast<int4*>(target)[j]=reinterpret_cast<const int4*>(src)[j];
    } else {
      for(int64_t j=threadIdx.x;j<H;j+=blockDim.x) target[j]=src[j];
    }
  } else {
    using Reduce=hipcub::BlockReduce<float,block>;
    __shared__ typename Reduce::TempStorage temp;
    __shared__ float scale;
    float local=0;
    if(valid) for(int64_t j=threadIdx.x;j<H;j+=blockDim.x) local=fmaxf(local,fabsf(smoothed(input,smooth,t,e,H,j)));
    float maximum=Reduce(temp).Reduce(local,hipcub::Max());
    if(threadIdx.x==0) {
      scale=maximum==0 ? 1.0f : fmaxf(__fdiv_rn(maximum,Mode==1 ? 127.0f : 448.0f),FLT_MIN);
      scales[r]=scale;
    }
    __syncthreads();
    for(int64_t j=threadIdx.x;j<H;j+=blockDim.x) {
      float z=valid ? __fdiv_rn(smoothed(input,smooth,t,e,H,j),scale) : 0.0f;
      if constexpr(Mode==1) {
        // Finite input/smooth/product is the numerical precondition.
        z=isnan(z) ? 0.0f : fminf(127.0f,fmaxf(-127.0f,z));
        static_cast<int8_t*>(out)[dst+j]=int8_t(__float2int_rn(z));
      } else {
        z=fminf(448.0f,fmaxf(-448.0f,z));
        static_cast<c10::Float8_e4m3fn*>(out)[dst+j]=c10::Float8_e4m3fn(z);
      }
    }
  }
}

template<typename T,int Vec>
struct alignas(sizeof(T)*Vec) Vector { T v[Vec]; };

__device__ __forceinline__ float ordered_product(float a,float b) {
  // DTK's late HCU combine pass contracts even __fmul_rn/__fadd_rn and
  // clang contract(off). Keep this multiplication opaque to that pass so
  // the documented per-k FP32 rounding order is retained without new flags.
  float value;
  asm("v_mul_f32 %0, %1, %2" : "=v"(value) : "v"(a), "v"(b));
  return value;
}

template<typename T,int Vec>
__global__ void gather_rows(T* out,const T* input,const float* weights,const int32_t* inv,
    const int32_t* experts,const float* bias,const T* residual,const T* x2,
    int M,int H,int K,int Tcap,int E,int start,int end,int res_rows,float res_scale) {
  #pragma clang fp contract(off)
  int tiles=(int64_t(H)+blockDim.x*Vec-1)/(blockDim.x*Vec);
  int t=blockIdx.x/tiles;
  int64_t j=(int64_t(blockIdx.x%tiles)*blockDim.x+threadIdx.x)*Vec;
  if(t>=M || j>=H) return;
  float acc[Vec]={};
  #pragma unroll
  for(int v=0;v<Vec;++v) {
    if(j+v<H) {
      if(residual && t>=start && t<end) acc[v]=ordered_product(float(residual[int64_t(res_rows==1 ? 0 : t-start)*H+j+v]),res_scale);
      if(x2) acc[v]=__fadd_rn(acc[v],float(x2[int64_t(t)*H+j+v]));
    }
  }
  for(int k=0;k<K;++k) {
    int64_t f=int64_t(t)*K+k; int r=inv[f];
    if(r<0 || r>=Tcap) continue;
    int e=experts[r]; if(e<0 || (bias && e>=E)) continue;
    float w=weights[f];
    Vector<T,Vec> values;
    if constexpr(Vec>1) values=*reinterpret_cast<const Vector<T,Vec>*>(input+int64_t(r)*H+j);
    else values.v[0]=input[int64_t(r)*H+j];
    #pragma unroll
    for(int v=0;v<Vec;++v) {
      float z=float(values.v[v]);
      if(bias) z=__fadd_rn(z,bias[int64_t(e)*H+j+v]);
      acc[v]=__fadd_rn(acc[v],ordered_product(z,w));
    }
  }
  Vector<T,Vec> result;
  #pragma unroll
  for(int v=0;v<Vec;++v) result.v[v]=T(acc[v]);
  if constexpr(Vec>1) *reinterpret_cast<Vector<T,Vec>*>(out+int64_t(t)*H+j)=result;
  else out[int64_t(t)*H+j]=result.v[0];
}
__global__ void cumsum_kernel(int32_t* out,const int32_t* counts,int E) {
  using Scan=hipcub::BlockScan<int,block>;
  __shared__ typename Scan::TempStorage temp;
  int values[8],result[8];
  #pragma unroll
  for(int i=0;i<8;++i) { int e=threadIdx.x*8+i; values[i]=e<E ? counts[e] : 0; }
  Scan(temp).InclusiveSum(values,result);
  #pragma unroll
  for(int i=0;i<8;++i) { int e=threadIdx.x*8+i; if(e<E) out[e]=result[i]; }
}
} // namespace

int64_t moe_routing_workspace_size(torch::Tensor ids) {
  routing::tensor(ids,ids); TORCH_CHECK(ids.numel()<=INT_MAX,"route metadata exceeds INT32_MAX");
  const at::hip::OptionalHIPGuardMasqueradingAsCUDA guard(device_of(ids));
  return workspace_bytes(ids.numel());
}

void moe_routing_prepare_out(torch::Tensor ids,torch::Tensor weights,
    std::optional<torch::Tensor> expert_map,torch::Tensor counts,torch::Tensor offsets,
    torch::Tensor route_ids,torch::Tensor inv_perm,torch::Tensor token_ids,
    torch::Tensor token_weights,torch::Tensor m_indices,torch::Tensor valid_rows,
    torch::Tensor span_rows,torch::Tensor status,torch::Tensor workspace,
    int E,int alignment,std::optional<torch::Tensor> active_num,int expert_capacity) {
  routing::expert_shape(E,alignment); TORCH_CHECK(ids.dim()==2,"ids must be [M,K]");
  routing::ids_shape(ids,ids.size(0)); routing::map_shape(expert_map,ids);
  for(const auto& t:{ids,weights,counts,offsets,route_ids,inv_perm,token_ids,token_weights,m_indices,valid_rows,span_rows,status,workspace}) routing::tensor(t,ids);
  routing::dtype(weights,at::kFloat); routing::dtype(token_weights,at::kFloat); routing::dtype(workspace,at::kByte);
  TORCH_CHECK(weights.sizes()==ids.sizes() && inv_perm.sizes()==ids.sizes(),"ids/weights/inv_perm shape mismatch");
  for(const auto& t:{counts,offsets,route_ids,inv_perm,token_ids,m_indices,valid_rows,span_rows,status}) routing::dtype(t,at::kInt);
  for(const auto& t:{counts,offsets}) TORCH_CHECK(t.dim()==1 && t.numel()==E,"counts/offsets must be int32[E]");
  for(const auto& t:{valid_rows,span_rows,status}) TORCH_CHECK(t.dim()==1 && t.numel()==1,"device lengths/status must be int32[1]");
  TORCH_CHECK(expert_capacity>=0 && (!expert_capacity || alignment==1),"DropPad requires C>0 and alignment=1");
  int64_t required=expert_capacity ? int64_t(E)*expert_capacity : ids.numel()+int64_t(E)*(alignment-1);
  TORCH_CHECK(required<=INT_MAX && route_ids.numel()>=required && route_ids.numel()<=INT_MAX,"insufficient/overflowing routing capacity");
  for(const auto& t:{route_ids,token_ids,token_weights,m_indices}) TORCH_CHECK(t.dim()==1 && t.numel()==route_ids.numel(),"row metadata shape mismatch");
  if(active_num) { routing::tensor(*active_num,ids);routing::dtype(*active_num,at::kLong);TORCH_CHECK(active_num->numel()==1,"active_num must be a device int64 scalar"); }
  auto writes={counts,offsets,route_ids,inv_perm,token_ids,token_weights,m_indices,valid_rows,span_rows,status,workspace};
  routing::outputs(writes,{ids,weights});
  for(const auto& t:writes) { if(expert_map) routing::disjoint(t,*expert_map);if(active_num) routing::disjoint(t,*active_num); }
  const at::hip::OptionalHIPGuardMasqueradingAsCUDA guard(device_of(ids));
  int n=ids.numel();size_t key_storage=align_bytes(size_t(n)*8),scratch=scratch_bytes(n);
  TORCH_CHECK(workspace.dim()==1 && workspace.numel()>=workspace_bytes(n),"insufficient routing workspace");
  routing::vector_address(workspace,256);
  auto base=workspace.data_ptr<uint8_t>();auto keys=reinterpret_cast<uint64_t*>(base);
  auto sorted=reinterpret_cast<uint64_t*>(base+key_storage);
  auto raw=reinterpret_cast<int32_t*>(base+2*key_storage);
  auto temp=base+2*key_storage+align_bytes(routing::max_experts*4);
  hipStream_t stream=at::hip::getCurrentHIPStream();
  clear(counts,0,stream);clear(route_ids,0xff,stream);clear(inv_perm,0xff,stream);
  clear(token_ids,0xff,stream);clear(m_indices,0xff,stream);clear(token_weights,0,stream);
  routing::RouteInfo info{E,expert_map ? int(expert_map->numel()) : -1,int(route_ids.numel()),ids.scalar_type()==at::kLong};
  if(n) {
    make_keys<<<(int64_t(n)+block-1)/block,block,0,stream>>>(ids.data_ptr(),expert_map ? expert_map->data_ptr<int32_t>() : nullptr,keys,counts.data_ptr<int32_t>(),n,info);
    TORCH_CHECK(hipcub::DeviceRadixSort::SortKeys(temp,scratch,keys,sorted,n,0,key_bits,stream)==hipSuccess,"routing sort failed");
  }
  make_layout<<<1,block,0,stream>>>(counts.data_ptr<int32_t>(),offsets.data_ptr<int32_t>(),raw,valid_rows.data_ptr<int32_t>(),span_rows.data_ptr<int32_t>(),status.data_ptr<int32_t>(),E,alignment,active_num ? active_num->data_ptr<int64_t>() : nullptr,expert_capacity);
  if(n) emit_routes<<<(int64_t(n)+block-1)/block,block,0,stream>>>(sorted,weights.data_ptr<float>(),raw,counts.data_ptr<int32_t>(),offsets.data_ptr<int32_t>(),route_ids.data_ptr<int32_t>(),inv_perm.data_ptr<int32_t>(),token_ids.data_ptr<int32_t>(),token_weights.data_ptr<float>(),m_indices.data_ptr<int32_t>(),n,ids.size(1),E);
  launched();
}

void moe_routing_scatter_out(torch::Tensor out,std::optional<torch::Tensor> out_scale,
    torch::Tensor input,torch::Tensor token_ids,torch::Tensor m_indices,std::optional<torch::Tensor> smooth,int mode) {
  for(const auto& t:{out,input,token_ids,m_indices}) routing::tensor(t,input);
  TORCH_CHECK(input.dim()==2 && out.dim()==2 && input.size(1)>0 && input.size(1)<=INT_MAX && out.size(1)==input.size(1),"scatter expects matching 2D widths");
  TORCH_CHECK(input.size(0)<=INT_MAX && out.size(0)<=INT_MAX,"scatter row count exceeds INT32_MAX");
  TORCH_CHECK(input.scalar_type()==at::kHalf || input.scalar_type()==at::kBFloat16 || input.scalar_type()==at::kFloat,"scatter input must be floating point");
  for(const auto& t:{token_ids,m_indices}) { routing::dtype(t,at::kInt);TORCH_CHECK(t.dim()==1 && t.numel()==out.size(0),"scatter metadata must be int32[Tcap]"); }
  TORCH_CHECK(mode>=0 && mode<=2,"unsupported quantization mode");
  TORCH_CHECK(mode!=0 || (!smooth && !out_scale && out.scalar_type()==input.scalar_type()),"unquantized scatter preserves dtype and has no smooth/scale");
  TORCH_CHECK(mode!=1 || out.scalar_type()==at::kChar,"INT8 output required");
  TORCH_CHECK(mode!=2 || out.scalar_type()==at::kFloat8_e4m3fn,"E4M3FN output required");
  routing::outputs({out},{input,token_ids,m_indices});
  int E=0;
  if(smooth) { routing::tensor(*smooth,input);routing::dtype(*smooth,at::kFloat);TORCH_CHECK(smooth->dim()==2 && smooth->size(1)==input.size(1) && smooth->size(0)>=1 && smooth->size(0)<=routing::max_experts,"smooth must be FP32[E,H]");E=smooth->size(0);routing::disjoint(out,*smooth); }
  if(mode) {
    TORCH_CHECK(out_scale.has_value(),"quantized scatter requires out_scale");
    routing::tensor(*out_scale,input);routing::dtype(*out_scale,at::kFloat);
    TORCH_CHECK(out_scale->numel()==out.size(0) && (out_scale->dim()==1 || (out_scale->dim()==2 && out_scale->size(1)==1)),"out_scale must be FP32[Tcap] or [Tcap,1]");
    routing::outputs({*out_scale},{out,input,token_ids,m_indices}); if(smooth) routing::disjoint(*out_scale,*smooth);
  }
  if(!out.size(0)) return;
  const at::hip::OptionalHIPGuardMasqueradingAsCUDA guard(device_of(input));
  auto stream=at::hip::getCurrentHIPStream();
  VLLM_DISPATCH_FLOATING_TYPES(input.scalar_type(),"moe_routing_scatter",[&] {
    auto launch=[&]<int Mode>() { scatter_rows<scalar_t,Mode><<<out.size(0),block,0,stream>>>(input.data_ptr<scalar_t>(),out.data_ptr(),out_scale ? out_scale->data_ptr<float>() : nullptr,token_ids.data_ptr<int32_t>(),m_indices.data_ptr<int32_t>(),smooth ? smooth->data_ptr<float>() : nullptr,input.size(0),input.size(1),E,out.size(0)); };
    if(mode==0) launch.template operator()<0>(); else if(mode==1) launch.template operator()<1>(); else launch.template operator()<2>();
  }); launched();
}

void moe_routing_gather_out(torch::Tensor out,torch::Tensor expert_output,torch::Tensor weights,
    torch::Tensor inv_perm,torch::Tensor m_indices,std::optional<torch::Tensor> bias,
    std::optional<torch::Tensor> residual,double res_scale,int residual_start,int residual_end,std::optional<torch::Tensor> x2) {
  for(const auto& t:{out,expert_output,weights,inv_perm,m_indices}) routing::tensor(t,out);
  TORCH_CHECK(out.dim()==2 && expert_output.dim()==2 && out.size(1)==expert_output.size(1) && out.size(1)>0 && out.size(1)<=INT_MAX,"gather width mismatch");
  TORCH_CHECK(out.scalar_type()==at::kHalf || out.scalar_type()==at::kBFloat16 || out.scalar_type()==at::kFloat,"gather expects FP16/BF16/FP32");
  routing::dtype(expert_output,out.scalar_type()); routing::dtype(weights,at::kFloat);routing::dtype(inv_perm,at::kInt);routing::dtype(m_indices,at::kInt);
  routing::ids_shape(inv_perm,out.size(0)); TORCH_CHECK(weights.sizes()==inv_perm.sizes(),"gather weights/inv_perm mismatch");
  TORCH_CHECK(m_indices.dim()==1 && m_indices.numel()==expert_output.size(0) && expert_output.size(0)<=INT_MAX,"gather m_indices shape mismatch");
  int M=out.size(0),H=out.size(1),K=weights.size(1),E=0;
  if(residual_end==-1) residual_end=M;
  TORCH_CHECK(residual_start>=0 && residual_start<=residual_end && residual_end<=M,"invalid residual interval");
  routing::outputs({out},{expert_output,weights,inv_perm,m_indices});
  if(bias) {routing::tensor(*bias,out);routing::dtype(*bias,at::kFloat);TORCH_CHECK(bias->dim()==2 && bias->size(1)==H && bias->size(0)>=1 && bias->size(0)<=routing::max_experts,"bias must be FP32[E,Hout]");E=bias->size(0);routing::disjoint(out,*bias);}
  if(residual) {routing::tensor(*residual,out);routing::dtype(*residual,out.scalar_type());TORCH_CHECK(residual->dim()==2 && residual->size(1)==H && (residual->size(0)==1 || residual->size(0)==residual_end-residual_start),"residual must be [R,Hout] or [1,Hout]");routing::disjoint(out,*residual);}
  if(x2) {routing::tensor(*x2,out);TORCH_CHECK(x2->sizes()==out.sizes() && x2->scalar_type()==out.scalar_type(),"x2 must match out");routing::disjoint(out,*x2);}
  if(!M) return;
  const at::hip::OptionalHIPGuardMasqueradingAsCUDA guard(device_of(out));auto stream=at::hip::getCurrentHIPStream();
  VLLM_DISPATCH_FLOATING_TYPES(out.scalar_type(),"moe_routing_gather",[&] {
    auto launch=[&]<int Vec>() { int64_t grid=int64_t(M)*((int64_t(H)+block*Vec-1)/(block*Vec));TORCH_CHECK(grid<=INT_MAX,"gather grid too large");gather_rows<scalar_t,Vec><<<grid,block,0,stream>>>(out.data_ptr<scalar_t>(),expert_output.data_ptr<scalar_t>(),weights.data_ptr<float>(),inv_perm.data_ptr<int32_t>(),m_indices.data_ptr<int32_t>(),bias ? bias->data_ptr<float>() : nullptr,residual ? residual->data_ptr<scalar_t>() : nullptr,x2 ? x2->data_ptr<scalar_t>() : nullptr,M,H,K,expert_output.size(0),E,residual_start,residual_end,residual ? residual->size(0) : 0,float(res_scale));};
    constexpr int vec=16/sizeof(scalar_t);
    if(H%vec==0 && reinterpret_cast<uintptr_t>(out.data_ptr())%16==0 && reinterpret_cast<uintptr_t>(expert_output.data_ptr())%16==0) launch.template operator()<vec>();else launch.template operator()<1>();
  }); launched();
}

void moe_routing_cumsum_out(torch::Tensor out,torch::Tensor counts) {
  routing::tensor(out,counts);routing::tensor(counts,counts);routing::dtype(out,at::kInt);routing::dtype(counts,at::kInt);
  TORCH_CHECK(counts.dim()==1 && out.sizes()==counts.sizes() && counts.numel()>=1 && counts.numel()<=routing::max_experts,"cumsum requires int32[E]");routing::disjoint(out,counts);
  const at::hip::OptionalHIPGuardMasqueradingAsCUDA guard(device_of(counts));
  cumsum_kernel<<<1,block,0,at::hip::getCurrentHIPStream()>>>(out.data_ptr<int32_t>(),counts.data_ptr<int32_t>(),counts.numel());launched();
}
} // namespace aiter
