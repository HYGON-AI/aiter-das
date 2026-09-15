// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
// SPDX-License-Identifier: MIT

#pragma once
#include "fp8.cuh"
#include "fp16.cuh"
namespace aiter_paged_mqa_hcu {

// ID6: every request has its own page table. No sharing assumption is made.
template<int H,int S,int R>
__global__ __launch_bounds__(256) void paged_mqa_fp8_single(const uint8_t* q,const uint8_t* k,const float* w,
 const int* ctx,const int* tb,float* out,int B,int N,int tw) {
    grouped_device<uint8_t,R,H,128,S,S*4,4,64,true,1,false>(q,k,(const float*)(k+S*128),w,B,0,S*132,N,tw,ctx,out,tb,nullptr,blockIdx.y);
}
template<int H,int S,int R>
__global__ __launch_bounds__(256) void paged_mqa_fp16_single(const uint16_t* q,const uint16_t* k,const float* w,
 const int* ctx,const int* tb,float* out,int B,int N,int tw,int tokens) {
    const float* scales=(const float*)((const uint8_t*)k+int64_t(tokens)*256);
    grouped_half_device<uint16_t,R,H,128,S,S*4,4,64,1>(q,k,w,B,0,S*256,N,tw,ctx,out,tb,scales,blockIdx.y);
}
template<int QT,int S>
__global__ __launch_bounds__(256) void paged_mqa_grouped(const uint8_t* q,const uint8_t* k,const float* w,
 const int* ctx,const int* tb,float* out,int B,int N,int tw,const int* flags,const int* cctx,const int* ctb){
 const int g=blockIdx.y;
 const int chunks=(N-1)/(S*1024)+1;
 bool bad=false;
 for(int j=threadIdx.x%64;j<chunks;j+=64)bad|=flags[g*chunks+j]<0;
 if(__ballot(bad)==0){
    grouped_device<uint8_t,1,32*QT,128,64,256,4,64,true,QT>(q,k,(const float*)(k+8192),w,B,0,8448,N,((N-1)/64+1),cctx,out,ctb,nullptr,g);
 }else{
    for(int i=0;i<QT&&g*QT+i<B;++i){
      grouped_device<uint8_t,1,32,128,S,S*4,4,64,true,1>(q,k,(const float*)(k+S*128),w,B,0,S*132,N,tw,ctx,out,tb,nullptr,g*QT+i);
      __syncthreads();
    }
 }
}
template<int QT,int S>
__global__ __launch_bounds__(256) void paged_mqa_half_grouped(const uint16_t* q,const uint16_t* k,const float* w,
 const int* ctx,const int* tb,float* out,int B,int N,int tw,int tokens,const int* flags,const int* cctx,const int* ctb){
 const int g=blockIdx.y;const float* scales=(const float*)((const uint8_t*)k+int64_t(tokens)*256);
 const int chunks=(N-1)/(S*1024)+1;
 bool bad=false;
 for(int j=threadIdx.x%64;j<chunks;j+=64)bad|=flags[g*chunks+j]<0;
 if(__ballot(bad)==0){
    grouped_half_device<uint16_t,1,32*QT,128,64,256,4,64,QT>(q,k,w,B,0,16384,N,((N-1)/64+1),cctx,out,ctb,scales,g);
 }else{
    for(int i=0;i<QT&&g*QT+i<B;++i){
      grouped_half_device<uint16_t,1,32,128,S,S*4,4,64,1>(q,k,w,B,0,S*256,N,tw,ctx,out,tb,scales,g*QT+i);
      __syncthreads();
    }
 }
}

} // namespace aiter_paged_mqa_hcu
