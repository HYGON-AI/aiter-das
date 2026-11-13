// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
#pragma once
#include <torch/all.h>
#include <hip/hip_runtime.h>
#include <cstdint>
#include <climits>
#include <initializer_list>
#include <type_traits>

namespace aiter { namespace routing {
constexpr int max_experts = 1200;

inline void tensor(const torch::Tensor& t, const torch::Tensor& like) {
  TORCH_CHECK(t.is_cuda() && t.device() == like.device(), "routing tensors must be on the same GPU");
  TORCH_CHECK(t.is_contiguous(), "routing tensors must be contiguous");
  TORCH_CHECK(!t.requires_grad(), "routing is forward-only");
}
inline void dtype(const torch::Tensor& t, at::ScalarType type) {
  TORCH_CHECK(t.scalar_type() == type, "unexpected routing dtype");
}
inline void disjoint(const torch::Tensor& a, const torch::Tensor& b) {
  if (!a.numel() || !b.numel()) return;
  auto x=reinterpret_cast<uintptr_t>(a.data_ptr());
  auto y=reinterpret_cast<uintptr_t>(b.data_ptr());
  TORCH_CHECK(x+a.nbytes() <= y || y+b.nbytes() <= x, "routing inputs and outputs must not overlap");
}
inline void outputs(std::initializer_list<torch::Tensor> writes,
                    std::initializer_list<torch::Tensor> reads) {
  for (auto a=writes.begin(); a!=writes.end(); ++a) {
    for (auto b=a+1; b!=writes.end(); ++b) disjoint(*a,*b);
    for (const auto& b:reads) disjoint(*a,b);
  }
}
inline void expert_shape(int E, int A) {
  TORCH_CHECK(E>=1 && E<=max_experts, "local experts must be in [1,1200]");
  TORCH_CHECK(A>0 && (A & (A-1))==0, "alignment must be a positive power of two");
}
inline void ids_shape(const torch::Tensor& ids, int64_t M, bool bounded=true) {
  TORCH_CHECK(ids.dim()==2 && ids.size(0)==M, "ids must have shape [M,K]");
  TORCH_CHECK(ids.scalar_type()==at::kInt || ids.scalar_type()==at::kLong, "ids must be int32 or int64");
  TORCH_CHECK(ids.numel()<=INT_MAX && M<=INT_MAX, "route metadata exceeds INT32_MAX");
  if(bounded) TORCH_CHECK(ids.size(1)>=1 && ids.size(1)<=30, "topk must be in [1,30]");
}
inline void map_shape(const std::optional<torch::Tensor>& map, const torch::Tensor& like) {
  if(map) { tensor(*map,like); dtype(*map,at::kInt); TORCH_CHECK(map->dim()==1 && map->numel()<=INT_MAX,"expert_map must be int32[G]"); }
}
inline void vector_address(const torch::Tensor& t, int alignment) {
  TORCH_CHECK(!t.numel() || reinterpret_cast<uintptr_t>(t.data_ptr())%alignment==0,
              "legacy EP vector path requires aligned storage offset");
}
struct RouteInfo {
  int experts, map_size, capacity;
  bool ids64;
  template<typename Id, bool Mapped=true>
  __device__ __forceinline__ int local_typed(const Id* ids, int64_t f, const int32_t* map) const {
    int64_t e=ids[f];
    if constexpr(Mapped) { if(map_size >= 0) {
      if(e<0 || e>=map_size) return -1;
      e=map[e];
    } }
    return e>=0 && e<experts ? static_cast<int>(e) : -1;
  }
  __device__ int local(const void* ids, int64_t f, const int32_t* map) const {
    int64_t e=ids64 ? static_cast<const int64_t*>(ids)[f] : static_cast<const int32_t*>(ids)[f];
    if(map_size >= 0) {
      if(e<0 || e>=map_size) return -1;
      e=map[e];
    }
    return e>=0 && e<experts ? static_cast<int>(e) : -1;
  }
  __device__ int claim(int32_t* cursor, int e) const {
    int row=atomicAdd(cursor+e,1);
    // Invalid caller-provided counts/starts must never write outside capacity.
    // A C++ noreturn trap makes DTK carry a deferred termination mask through
    // the rest of these large kernels. Trap at the failed bounds check itself.
    if(row<0 || row>=capacity) asm volatile("s_trap 2" ::: "memory");
    return row;
  }
};

inline RouteInfo legacy_scatter_check(const torch::Tensor& input,
    const torch::Tensor& ids, const std::optional<torch::Tensor>& map,
    const torch::Tensor& cursor, const torch::Tensor& out,
    const torch::Tensor& scale, const torch::Tensor& mi, const torch::Tensor& inv,
    int E,int A, const std::optional<torch::Tensor>& smooth=std::nullopt,
    const std::optional<torch::Tensor>& input_scale=std::nullopt) {
  expert_shape(E,A);
  for(const auto& t:{input,ids,cursor,out,scale,mi,inv}) tensor(t,input);
  TORCH_CHECK(input.dim()==2 && out.dim()==2 && input.size(1)>0 && input.size(1)<=65536,
              "legacy scatter expects 2D input/out, 1<=H<=65536");
  TORCH_CHECK(input.size(1)%16==0 && out.size(1)==input.size(1),"legacy scatter requires H divisible by 16 and matching out width");
  ids_shape(ids,input.size(0)); map_shape(map,input);
  TORCH_CHECK(out.size(0)<=INT_MAX && cursor.dim()==1 && cursor.numel()==E,"invalid cursor/capacity");
  for(const auto& t:{cursor,mi,inv}) dtype(t,at::kInt);
  dtype(scale,at::kFloat);
  TORCH_CHECK(mi.dim()==1 && mi.numel()==out.size(0) && scale.numel()==out.size(0) &&
              (scale.dim()==1 || (scale.dim()==2 && scale.size(1)==1)) && inv.sizes()==ids.sizes(),"invalid scatter output shape");
  outputs({cursor,out,scale,mi,inv},{input,ids});
  if(map) for(const auto& t:{cursor,out,scale,mi,inv}) disjoint(t,*map);
  // Smooth kernels use vectors of 16 elements; the other paths need 16 bytes.
  vector_address(input,smooth ? 16*input.element_size() : std::max<int>(16,8*input.element_size()));
  vector_address(out,16);
  if(smooth) {
    tensor(*smooth,input); dtype(*smooth,at::kFloat);
    TORCH_CHECK(smooth->dim()==2 && smooth->size(0)==E && smooth->size(1)==input.size(1),"smooth must be FP32[E,H]");
    vector_address(*smooth,64);
    for(const auto& t:{cursor,out,scale,mi,inv}) disjoint(t,*smooth);
  }
  if(input_scale) {
    tensor(*input_scale,input); dtype(*input_scale,at::kFloat);
    TORCH_CHECK(input_scale->numel()==input.size(0) && (input_scale->dim()==1 || (input_scale->dim()==2 && input_scale->size(1)==1)),"input scale must be [M] or [M,1]");
    for(const auto& t:{cursor,out,scale,mi,inv}) disjoint(t,*input_scale);
  }
  return {E,map ? static_cast<int>(map->numel()) : -1,static_cast<int>(out.size(0)),ids.scalar_type()==at::kLong};
}
}} // namespace aiter::routing
