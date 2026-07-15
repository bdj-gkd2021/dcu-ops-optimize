/***************************************************************************************************
 * Copyright (c) 2023 - 2023 NVIDIA CORPORATION & AFFILIATES. All rights reserved.
 * SPDX-License-Identifier: BSD-3-Clause
 *
 * Redistribution and use in source and binary forms, with or without
 * modification, are permitted provided that the following conditions are met:
 *
 * 1. Redistributions of source code must retain the above copyright notice, this
 * list of conditions and the following disclaimer.
 *
 * 2. Redistributions in binary form must reproduce the above copyright notice,
 * this list of conditions and the following disclaimer in the documentation
 * and/or other materials provided with the distribution.
 *
 * 3. Neither the name of the copyright holder nor the names of its
 * contributors may be used to endorse or promote products derived from
 * this software without specific prior written permission.
 *
 * THIS SOFTWARE IS PROVIDED BY THE COPYRIGHT HOLDERS AND CONTRIBUTORS "AS IS"
 * AND ANY EXPRESS OR IMPLIED WARRANTIES, INCLUDING, BUT NOT LIMITED TO, THE
 * IMPLIED WARRANTIES OF MERCHANTABILITY AND FITNESS FOR A PARTICULAR PURPOSE ARE
 * DISCLAIMED. IN NO EVENT SHALL THE COPYRIGHT HOLDER OR CONTRIBUTORS BE LIABLE
 * FOR ANY DIRECT, INDIRECT, INCIDENTAL, SPECIAL, EXEMPLARY, OR CONSEQUENTIAL
 * DAMAGES (INCLUDING, BUT NOT LIMITED TO, PROCUREMENT OF SUBSTITUTE GOODS OR
 * SERVICES; LOSS OF USE, DATA, OR PROFITS; OR BUSINESS INTERRUPTION) HOWEVER
 * CAUSED AND ON ANY THEORY OF LIABILITY, WHETHER IN CONTRACT, STRICT LIABILITY,
 * OR TORT (INCLUDING NEGLIGENCE OR OTHERWISE) ARISING IN ANY WAY OUT OF THE USE
 * OF THIS SOFTWARE, EVEN IF ADVISED OF THE POSSIBILITY OF SUCH DAMAGE.
 *
 **************************************************************************************************/
#pragma once

#include <cute/arch/mma_gfx938.hpp>

#include <cute/atom/mma_traits.hpp>
#include <cute/layout.hpp>

namespace cute
{

////////////////////////////v_mmac_f32_16x16x64_f8///////////////////////////////////////////////////
template <>
struct MMA_Traits<GFX938_16x16x64_F32F8F8F32E4M3E4M3_NT>
{
  using ElementDVal = float;
  using ElementAVal = float_e4m3_t;
  using ElementBVal = float_e4m3_t;
  using ElementCVal = float;
  using Shape_MNK = Shape<_16,_16,_64>;
  using ThrID   = Layout<_64>;

  using ALayout = Layout<Shape<Shape<_16, _4>,_16>, //_1表示to到t1  _64表示to到t16 _16表示t0内部之间
                          Stride<Stride<_1,_256>,_16>>; //Stride<Stride<_1,_128>,_16>>;
  using BLayout = Layout<Shape <Shape <_16, _4>,_16>,
                         Stride<Stride<_1,_256>,_16>>; //Stride<Stride< _1,_128>,_16>>;

  using CLayout = Layout<Shape <Shape <_16, _4>, _4>,
                         Stride<Stride< _1, _16>, _64>>;
};

//////////////////////v_mmac_f32_16x16x32 concatenate by 2*16x16x16//////////////////////////////
 template <>
 struct MMA_Traits<GFX938_16x16x32_F32F16F16F32_NT_LIT>
 {
   using ElementDVal = float;
   using ElementAVal = half_t;
   using ElementBVal = half_t;
   using ElementCVal = float;
 
 
   using Shape_MNK = Shape<_16,_16,_32>;
   using ThrID   = Layout<_64>;
   using ALayout = Layout<Shape<Shape<_16, _4>,Shape<_4, _2>>,
                           Stride<Stride<_1,_64>,Stride<_16,_256>>>;
   
   using BLayout = Layout<Shape <Shape <_16, _4>,_8>,
                          Stride<Stride< _1,_128>,_16>>;
   using CLayout = Layout<Shape <Shape <_16, _4>, _4>,
                          Stride<Stride< _16,_4>,_1>>;
 };
 
 template <>
 struct MMA_Traits<GFX938_16x16x32_F32BF16BF16F32_NT_LIT>
       : MMA_Traits<GFX938_16x16x32_F32F16F16F32_NT_LIT>
 {
   using ElementDVal = float;
   using ElementAVal = bfloat16_t;
   using ElementBVal = bfloat16_t;
   using ElementCVal = float;
 };

//////////////////////v_mmac_f32_16x32x16_f16 concatenate by 2*16x16x16//////////////////////////////
template <>
struct MMA_Traits<GFX938_16x32x16_F32F16F16F32_NT_LIT>
{
  using ElementDVal = float;
  using ElementAVal = half_t;
  using ElementBVal = half_t;
  using ElementCVal = float;


  using Shape_MNK = Shape<_16, _32, _16>;
  using ThrID = Layout<_64>;
  using ALayout = Layout<Shape<Shape<_16, _4>, _4>,
                          Stride<Stride<_1, _64>, _16>>;
  using BLayout = Layout<Shape<Shape<_16, _4>, Shape<_2, _4>>,
                          Stride<Stride<_1, _128>, Stride<_16, _32>>>;

  using CLayout = Layout<Shape<Shape<_16, _4>, Shape<_8>>,
                         Stride<Stride<_1, _16>, Stride<_64>>>;

};

template <>
struct MMA_Traits<GFX938_16x32x16_F32BF16BF16F32_NT_LIT>
      : MMA_Traits<GFX938_16x32x16_F32F16F16F32_NT_LIT>
{
  using ElementDVal = float;
  using ElementAVal = bfloat16_t;
  using ElementBVal = bfloat16_t;
  using ElementCVal = float;
};

template <>
struct MMA_Traits<GFX938_16x16x64_F32F8F8F32E4M3E4M3_NT_LIT>
{
  using ElementDVal = float;
  using ElementAVal = float_e4m3_t;
  using ElementBVal = float_e4m3_t;
  using ElementCVal = float;
  using Shape_MNK = Shape<_16,_16,_64>;
  using ThrID   = Layout<_64>;

  using ALayout = Layout<Shape<Shape<_16, _4>,_16>, //_1表示to到t1  _64表示to到t16 _16表示t0内部之间
                          Stride<Stride<_1,_256>,_16>>; //Stride<Stride<_1,_128>,_16>>;
  using BLayout = Layout<Shape <Shape <_16, _4>,_16>,
                         Stride<Stride<_1,_256>,_16>>; //Stride<Stride< _1,_128>,_16>>;

  using CLayout = Layout<Shape <Shape <_16, _4>, _4>,
                         Stride<Stride< _1, _64>, _16>>;
};

 template <>
 struct MMA_Traits<GFX938_16x16x64_F32F8F8F32E4M3E4M3_NN_LIT>
  : MMA_Traits<GFX938_16x16x64_F32F8F8F32E4M3E4M3_NT_LIT>
 {
  using ALayout = Layout<Shape<Shape<_4, _16>,_16>,
                            Stride<Stride<_256,_1>,_16>>;
 };

template <>
struct MMA_Traits<GFX938_16x32x32_F32F8F8F32E4M3E4M3_NT> {
  using ElementDVal = float;
  using ElementAVal = float_e4m3_t;
  using ElementBVal = float_e4m3_t;
  using ElementCVal = float;

  using Shape_MNK = Shape<_16, _32, _32>;
  using ThrID = Layout<_64>;

  using ALayout = Layout<Shape<Shape<_16, _4>, _8>,   // (16 * 4) *8  16*4个线程 每个拷8个
                         Stride<Stride<_1, _128>, _16>>;
  using BLayout = Layout<Shape<Shape<_16, _4>, Shape<_2, _8>>,
                         Stride<Stride<_1, _256>, Stride<_16, _32>>>;//_1表示to到t1  _256表示to到t16 _16表示t0内部之间
  using CLayout = Layout<Shape<Shape<_16, _4>, Shape<_8>>,
                         Stride<Stride<_1, _16>, Stride<_64>>>;
};

//////////////////////v_mmac_f32_16x32x32_f8//////////////////////////////
template <>
struct MMA_Traits<GFX938_16x32x32_F32F8F8F32E4M3E4M3_NT_LIT> {
  using ElementDVal = float;
  using ElementAVal = float_e4m3_t;
  using ElementBVal = float_e4m3_t;
  using ElementCVal = float;

  using Shape_MNK = Shape<_16, _32, _32>;
  using ThrID = Layout<_64>;

  using ALayout = Layout<Shape<Shape<_16, _4>, _8>,   // (16 * 4) *8  16*4个线程 每个拷8个
                         Stride<Stride<_1, _128>, _16>>;
  using BLayout = Layout<Shape<Shape<_16, _4>, Shape<_2, _8>>,
                         Stride<Stride<_1, _256>, Stride<_16, _32>>>;//_1表示to到t1  _256表示to到t16 _16表示t0内部之间
  using CLayout = Layout<Shape<Shape<_16, _4>, Shape<_4,_2>>,
                         Stride<Stride<_1, _64>, Stride<_16,_256>>>;
};

template <>
struct MMA_Traits<GFX938_16x64x16_F32F8F8F32E4M3E4M3_NT> {
  using ElementDVal = float;
  using ElementAVal = float_e4m3_t;
  using ElementBVal = float_e4m3_t;
  using ElementCVal = float;

  using Shape_MNK = Shape<_16, _64, _16>;
  using ThrID = Layout<_64>;

  using ALayout = Layout<Shape<Shape<_16, _4>, _4>,   // (16 * 4) *8  16*4个线程 每个拷8个
                         Stride<Stride<_1, _64>, _16>>;
  using BLayout = Layout<Shape<Shape<_16, _4>, Shape<_4, _4>>,
                         Stride<Stride<_1, _256>, Stride<_16, _64>>>;//_1表示to到t1  _256表示to到t16 _16表示t0内部之间
  using CLayout = Layout<Shape<Shape<_16, _4>, Shape<_16>>,
                         Stride<Stride<_1, _16>, Stride<_64>>>;
};

template <>
struct MMA_Traits<GFX938_16x64x32_F32BF8BF8F32E5M2E5M2_NT> {
  using ElementDVal = float;
  using ElementAVal = float_e5m2_t;
  using ElementBVal = float_e5m2_t;
  using ElementCVal = float;

  using Shape_MNK = Shape<_16, _64, _32>;
  using ThrID = Layout<_64>;

  using ALayout = Layout<Shape<Shape<_16, _4>, _8>,
                          Stride<Stride<_1, _128>, _16>>;
  using BLayout = Layout<Shape<Shape<_16, _4>, Shape<_8, _4>>,
                          Stride<Stride<_4, _512>, Stride<_64, _1>>>;

  using CLayout = Layout<Shape<Shape <_16, _4>, Shape<_4, _4>>,
                         Stride<Stride<_1, _64>, Stride<_16, _256>>>;
};

template <>
struct MMA_Traits<GFX938_16x64x32_F32BF8BF8F32E5M2E5M2_NN>
      : MMA_Traits<GFX938_16x64x32_F32BF8BF8F32E5M2E5M2_NT>
{
  using BLayout = Layout<Shape<Shape<_4, _16>, Shape<_8, _4>>,
                          Stride<Stride<_512, _1>, Stride<_64, _16>>>;
};


template <>
struct MMA_Traits<GFX938_16x64x32_F32F8F8F32E4M3E4M3_NT> {
  using ElementDVal = float;
  using ElementAVal = float_e4m3_t;
  using ElementBVal = float_e4m3_t;
  using ElementCVal = float;

  using Shape_MNK = Shape<_16, _64, _32>;
  using ThrID = Layout<_64>;

  using ALayout = Layout<Shape<Shape<_16, _4>, _8>,
                          Stride<Stride<_1, _128>, _16>>;
  using BLayout = Layout<Shape<Shape<_16, _4>, Shape<_8, _4>>,
                          Stride<Stride<_4, _512>, Stride<_64, _1>>>;

  using CLayout = Layout<Shape<Shape <_16, _4>, Shape<_4, _4>>,
                         Stride<Stride<_1, _64>, Stride<_16, _256>>>;
};

template <>
struct MMA_Traits<GFX938_16x64x32_F32F8F8F32E4M3E4M3_NN>
      : MMA_Traits<GFX938_16x64x32_F32F8F8F32E4M3E4M3_NT>
{
  using BLayout = Layout<Shape<Shape<_4, _16>, Shape<_8, _4>>,
                          Stride<Stride<_512, _1>, Stride<_64, _16>>>;
};

template <>
struct MMA_Traits<GFX938_16x64x32_F32F8F8F32E4M3E4M3_NN_Blayout>
      : MMA_Traits<GFX938_16x64x32_F32F8F8F32E4M3E4M3_NT>
{
  using BLayout = Layout<Shape<Shape<_4, _16>, Shape<Shape<_4, _2>, _4>>,
                          Stride<Stride<_256, _1>, Stride<Stride<_64, _1024>, _16>>>;  
};

template <>
struct MMA_Traits<GFX938_16x64x32_F32F8F8F32E4M3E4M3_NT_BLayout>
      : MMA_Traits<GFX938_16x64x32_F32F8F8F32E4M3E4M3_NT>
{
  using Shape_MNK = Shape<_16, _32, _64>;
  using BLayout = Layout<Shape<Shape<_8, _8>, Shape<_8, _4>>,
                          Stride<Stride<_256, _1>, Stride<_32, _8>>>;
};

template <>
struct MMA_Traits<GFX938_16x64x64_F32F8F8F32E4M3E4M3_NT> {
  using ElementDVal = float;
  using ElementAVal = float_e4m3_t;
  using ElementBVal = float_e4m3_t;
  using ElementCVal = float;

  using Shape_MNK = Shape<_16, _64, _64>;
  using ThrID = Layout<_64>;

  using ALayout = Layout<Shape<Shape<_16, _4>, _16>,
                         Stride<Stride<_1, _256>, _16>>;

  using BLayout = Layout<Shape<Shape<_16, _4>, Shape<_16, _4>>,
                         Stride<Stride<_4, _1024>, Stride<_64, _1>>>;

  using CLayout = Layout<Shape<Shape<_16, _4>, Shape<_4, _4>>,
                         Stride<Stride<_1, _64>, Stride<_16, _256>>>;
};

template <>
struct MMA_Traits<GFX938_16x64x64_F32F8F8F32E4M3E4M3_NT_BLayout>
      : MMA_Traits<GFX938_16x64x64_F32F8F8F32E4M3E4M3_NT>
{
  using Shape_MNK = Shape<_16, _64, _64>;
  using BLayout = Layout<Shape< Shape<_4, _16>,  Shape<_16, _4>>,
                          Stride< Stride<_1024, _1>, Stride<_64, _16>>>;
};

//////////////////////v_mmac_f32_16x64x64_f8 concatenate by 4*16x32x16//////////////////////////////
template <>
struct MMA_Traits<GFX938_16x64x64_F32BF8BF8F32E5M2E5M2_NT_LIT>
{
  using ElementDVal = float;
  using ElementAVal = float_e5m2_t;
  using ElementBVal = float_e5m2_t;
  using ElementCVal = float;


  using Shape_MNK = Shape<_16, _64, _64>;
  using ThrID = Layout<_64>;
  using ALayout = Layout<Shape<Shape<_16, _4>, _16>,
                          Stride<Stride<_1, _256>, _16>>;
  using BLayout = Layout<Shape<Shape<_16, _4>, Shape<_16, Shape<_2,_2>>>,
                          Stride<Stride<_2, _1024>, Stride<_64, Stride<_1,_32>>>>;

  using CLayout = Layout<Shape<Shape <_16, _4>, Shape<_8, _2>>,
                         Stride<Stride<_1, _128>, Stride<_16, _512>>>;
};

template <>
struct MMA_Traits<GFX938_16x64x64_F32BF8BF8F32E5M2E5M2_NT_LIT_BLayout>
      : MMA_Traits<GFX938_16x64x64_F32BF8BF8F32E5M2E5M2_NT_LIT>
{
 
  using BLayout = Layout<Shape<Shape<_4, _16>, Shape<_16, _4>>,
                          Stride<Stride<_1024, _1>, Stride<_64, _16>>>;

};


template <>
struct MMA_Traits<GFX938_16x64x64_F32F8F8F32E4M3E4M3_NT_LIT>
{
  using ElementDVal = float;
  using ElementAVal = float_e4m3_t;
  using ElementBVal = float_e4m3_t;
  using ElementCVal = float;


  using Shape_MNK = Shape<_16, _64, _64>;
  using ThrID = Layout<_64>;
  using ALayout = Layout<Shape<Shape<_16, _4>, _16>,
                          Stride<Stride<_1, _256>, _16>>;
  using BLayout = Layout<Shape<Shape<_16, _4>, Shape<_16, Shape<_2,_2>>>,
                          Stride<Stride<_2, _1024>, Stride<_64, Stride<_1,_32>>>>;

  using CLayout = Layout<Shape<Shape <_16, _4>, Shape<_8, _2>>,
                         Stride<Stride<_1, _128>, Stride<_16, _512>>>;
};

template <>
struct MMA_Traits<GFX938_16x64x64_F32F8F8F32E4M3E4M3_NT_LIT_BLayout>
      : MMA_Traits<GFX938_16x64x64_F32F8F8F32E4M3E4M3_NT_LIT>
{
 
  using BLayout = Layout<Shape<Shape<_4, _16>, Shape<_16, _4>>,
                          Stride<Stride<_1024, _1>, Stride<_64, _16>>>;

};

} // namespace cute
