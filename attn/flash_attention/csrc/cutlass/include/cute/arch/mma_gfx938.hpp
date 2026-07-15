/***************************************************************************************************
 * Copyright (c) 2023 - 2024 NVIDIA CORPORATION & AFFILIATES. All rights reserved.
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

#include <cute/config.hpp>

#include <cute/arch/mma.hpp>


namespace cute
{
  ////////////////////////////v_mmac_16x16x32 concatenate by 2x16x16x16/////////////////////////////////////////////
  struct GFX938_16x16x32_F32F16F16F32_NT_LIT
  {
    using DRegisters = float[4];
    using ARegisters = half_t[8];
    using BRegisters = half_t[8];
    using CRegisters = float[4];
    // Register asm fma
    CUTE_HOST_DEVICE static void
    fma(float      & d0, float      & d1, float      & d2, float      & d3, 
        half_t const& a0, half_t const& a1,half_t const& a2, half_t const& a3,
        half_t const& a4, half_t const& a5,half_t const& a6, half_t const& a7,
        half_t const& b0, half_t const& b1,half_t const& b2, half_t const& b3,
        half_t const& b4, half_t const& b5,half_t const& b6, half_t const& b7,
        float const& c0, float const& c1, float const& c2, float const& c3)
    {
      #if defined(__gfx938__)  && defined(DCU_ASM)
        v4f c;
        v4f d;
        c.x = c0; c.y = c1; c.z = c2; c.w = c3;

        __fp16x4_t A0, A1, B0, B1;
        A0.x = a0; A0.y = a1; A0.z = a2; A0.w = a3;
        A1.x = a4; A1.y = a5; A1.z = a6; A1.w = a7;

        B0.x = b0; B0.y = b1; B0.z = b2; B0.w = b3;
        B1.x = b4; B1.y = b5; B1.z = b6; B1.w = b7;
        
        d = __builtin_hcu_mmac_f32_16x16x16_f16_lit_lts(A0,B0,c,true,false);
        d = __builtin_hcu_mmac_f32_16x16x16_f16_lit_lts(A1,B1,d,true,false);
       
        d0 = d.x;
        d1 = d.y;
        d2 = d.z;
        d3 = d.w;
      #endif
    }
    
  };

  struct GFX938_16x16x32_F32BF16BF16F32_NT_LIT
  {
    using DRegisters = float[4];
    using ARegisters = bfloat16_t[8];
    using BRegisters = bfloat16_t[8];
    using CRegisters = float[4];
    // Register asm fma
    CUTE_HOST_DEVICE static void
    fma(float      & d0, float      & d1, float      & d2, float      & d3, 
        bfloat16_t const& a0, bfloat16_t const& a1,bfloat16_t const& a2, bfloat16_t const& a3,
        bfloat16_t const& a4, bfloat16_t const& a5,bfloat16_t const& a6, bfloat16_t const& a7,
        bfloat16_t const& b0, bfloat16_t const& b1,bfloat16_t const& b2, bfloat16_t const& b3,
        bfloat16_t const& b4, bfloat16_t const& b5,bfloat16_t const& b6, bfloat16_t const& b7,
        float const& c0, float const& c1, float const& c2, float const& c3)
    {
      #if defined(__gfx938__)  && defined(DCU_ASM)
        v4f c;
        v4f d;
        c.x = c0; c.y = c1; c.z = c2; c.w = c3;

        cutlass::Array<bfloat16_t, 4> array_a0, array_a1, array_b0, array_b1;
        array_a0[0] = a0; array_a0[1] = a1; array_a0[2] = a2; array_a0[3] = a3;
        array_a1[0] = a4; array_a1[1] = a5; array_a1[2] = a6; array_a1[3] = a7;

        array_b0[0] = b0; array_b0[1] = b1; array_b0[2] = b2; array_b0[3] = b3;
        array_b1[0] = b4; array_b1[1] = b5; array_b1[2] = b6; array_b1[3] = b7;
        
        __bf16x4_t A0, A1, B0, B1;
        A0 = *reinterpret_cast<__bf16x4_t*>(&array_a0);
        A1 = *reinterpret_cast<__bf16x4_t*>(&array_a1);
        B0 = *reinterpret_cast<__bf16x4_t*>(&array_b0);
        B1 = *reinterpret_cast<__bf16x4_t*>(&array_b1);
        d = __builtin_hcu_mmac_f32_16x16x16_bf16_lit_lts(A0,B0,c,true,false);
        d = __builtin_hcu_mmac_f32_16x16x16_bf16_lit_lts(A1,B1,d,true,false);

        
        // debug
        // v4f d_;
        // d_ = __builtin_hcu_mmac_f32_16x16x16_bf16_lit_lts(A0,B0,c,true,false);
        // d = __builtin_hcu_mmac_f32_16x16x16_bf16_lit_lts(A1,B1,d_,true,false);
        // if (blockIdx.x == 0) {
        //   printf("cute 16x16x32 tid:%d A0:%10.4f %10.4f %10.4f %10.4f A1:%10.4f %10.4f %10.4f %10.4f "
        //     "B0:%10.4f %10.4f %10.4f %10.4f B1:%10.4f %10.4f %10.4f %10.4f "
        //     "C0:%10.4f %10.4f %10.4f %10.4f "
        //     "D0:%10.4f %10.4f %10.4f %10.4f D1:%10.4f %10.4f %10.4f %10.4f\n", 
        //     threadIdx.x, float(a0), float(a1), float(a2), float(a3), float(a4), float(a5), float(a6), float(a7), 
        //     float(b0), float(b1), float(b2), float(b3), float(b4), float(b5), float(b6), float(b7), 
        //     c0, c1, c2, c3, d_.x, d_.y, d_.z, d_.w, d.x, d.y, d.z, d.w
        //   );
        // }
       
        d0 = d.x;
        d1 = d.y;
        d2 = d.z;
        d3 = d.w;
      #endif
    }
    
  };

  ////////////////////////////v_mmac_16x32x16 concatenate by 2x16x16x16/////////////////////////////////////////////
  struct GFX938_16x32x16_F32F16F16F32_NT_LIT
  {
    using DRegisters = float[8];
    using ARegisters = half_t[4];
    using BRegisters = half_t[8];
    using CRegisters = float[8];

    // Register asm fma
    CUTE_HOST_DEVICE static void
    fma(float      & d0, float      & d1, float      & d2, float      & d3, 
        float      & d4, float      & d5, float      & d6, float      & d7, 
        half_t const& a0, half_t const& a1,half_t const& a2, half_t const& a3,
        half_t const& b0, half_t const& b1,half_t const& b2, half_t const& b3,
        half_t const& b4, half_t const& b5,half_t const& b6, half_t const& b7,
        float const& c0, float const& c1, float const& c2, float const& c3,
        float const& c4, float const& c5, float const& c6, float const& c7)
    {

      #if defined(__gfx938__)  && defined(DCU_ASM)

        v4f C0,C1;
        v4f D0,D1;

        C0.x = c0;  C0.y = c1;  C0.z = c2;  C0.w = c3;
        C1.x = c4;  C1.y = c5;  C1.z = c6;  C1.w = c7;
        // C0.x = 0;  C0.y = 0;  C0.z = 0;  C0.w = 0;
        // C1.x = 0;  C1.y = 0;  C1.z = 0;  C1.w = 0;

        __fp16x4_t A,B0,B1;

        A.x  = a0; A.y  = a1; A.z  = a2; A.w  = a3;
        B0.x = b0; B0.y = b1; B0.z = b2; B0.w = b3;
        B1.x = b4; B1.y = b5; B1.z = b6; B1.w = b7;

        D0 = __builtin_hcu_mmac_f32_16x16x16_f16_lit_lts(A, B0, C0,true,false);
        D1 = __builtin_hcu_mmac_f32_16x16x16_f16_lit_lts(A, B1, C1,true,false);
      
        d0 = D0.x;  d1 = D0.y;    d2 = D0.z;  d3 = D0.w;
        d4 = D1.x;  d5 = D1.y;    d6 = D1.z;  d7 = D1.w;
        #endif
    }
  };

  struct GFX938_16x32x16_F32BF16BF16F32_NT_LIT
  {
    using DRegisters = float[8];
    using ARegisters = bfloat16_t[4];
    using BRegisters = bfloat16_t[8];
    using CRegisters = float[8];

    // Register asm fma
    CUTE_HOST_DEVICE static void
    fma(float      & d0, float      & d1, float      & d2, float      & d3, 
        float      & d4, float      & d5, float      & d6, float      & d7, 
        bfloat16_t const& a0, bfloat16_t const& a1,bfloat16_t const& a2, bfloat16_t const& a3,
        bfloat16_t const& b0, bfloat16_t const& b1,bfloat16_t const& b2, bfloat16_t const& b3,
        bfloat16_t const& b4, bfloat16_t const& b5,bfloat16_t const& b6, bfloat16_t const& b7,
        float const& c0, float const& c1, float const& c2, float const& c3,
        float const& c4, float const& c5, float const& c6, float const& c7)
    {

      #if defined(__gfx938__) && defined(DCU_ASM)

        v4f C0,C1;
        v4f D0,D1;

        C0.x = c0;  C0.y = c1;  C0.z = c2;  C0.w = c3;
        C1.x = c4;  C1.y = c5;  C1.z = c6;  C1.w = c7;

        cutlass::Array<bfloat16_t, 4> array_a0;
        cutlass::Array<bfloat16_t, 4> array_b0, array_b1;

        array_a0[0] = a0; array_a0[1] = a1; array_a0[2] = a2; array_a0[3] = a3;

        array_b0[0] = b0; array_b0[1] = b1; array_b0[2] = b2; array_b0[3] = b3;
        array_b1[0] = b4; array_b1[1] = b5; array_b1[2] = b6; array_b1[3] = b7;

        __bf16x4_t A,B0,B1;
        A = *reinterpret_cast<__bf16x4_t*>(&array_a0);
        B0 = *reinterpret_cast<__bf16x4_t*>(&array_b0);
        B1 = *reinterpret_cast<__bf16x4_t*>(&array_b1);

        D0 = __builtin_hcu_mmac_f32_16x16x16_bf16_lit_lts(A, B0, C0,true,false);
        D1 = __builtin_hcu_mmac_f32_16x16x16_bf16_lit_lts(A, B1, C1,true,false);
      
        // debug
        // if (blockIdx.x == 0) {
        //   printf("cute 16x32x16 tid:%d A:%10.4f %10.4f %10.4f %10.4f B0:%10.4f %10.4f %10.4f %10.4f "
        //     "B1:%10.4f %10.4f %10.4f %10.4f C0:%10.4f %10.4f %10.4f %10.4f C1:%10.4f %10.4f %10.4f %10.4f"
        //     "D0:%10.4f %10.4f %10.4f %10.4f D1:%10.4f %10.4f %10.4f %10.4f\n", 
        //     threadIdx.x, float(a0), float(a1), float(a2), float(a3), float(b0), float(b1), float(b2), float(b3), 
        //     float(b4), float(b5), float(b6), float(b7), c0, c1, c2, c3, c4, c5, c6, c7,
        //     D0.x, D0.y, D0.z, D0.w, D1.x, D1.y, D1.z, D1.w
        //   );
        // }

        d0 = D0.x;  d1 = D0.y;    d2 = D0.z;  d3 = D0.w;
        d4 = D1.x;  d5 = D1.y;    d6 = D1.z;  d7 = D1.w;
      #endif
    }
  };

  
  //add 16x64x16
  struct GFX938_16x64x16_F32F8F8F32E4M3E4M3_NT
  {
    using DRegisters = float[16];
    using ARegisters = float_e4m3_t[4];
    using BRegisters = float_e4m3_t[16];
    using CRegisters = float[16];
  };
 

  //add 16x16x64
  struct GFX938_16x16x64_F32F8F8F32E4M3E4M3_NT
  {
    using DRegisters = float[4];
    using ARegisters = float_e4m3_t[16];
    using BRegisters = float_e4m3_t[16];
    using CRegisters = float[4];

    // Register asm fma
    CUTE_HOST_DEVICE static void
    fma(float      & d0, float      & d1, float      & d2, float      & d3, 
        float_e4m3_t const& a0, float_e4m3_t const& a1,float_e4m3_t const& a2, float_e4m3_t const& a3,
        float_e4m3_t const& a4, float_e4m3_t const& a5,float_e4m3_t const& a6, float_e4m3_t const& a7,
        float_e4m3_t const& a8, float_e4m3_t const& a9,float_e4m3_t const& a10, float_e4m3_t const& a11,
        float_e4m3_t const& a12, float_e4m3_t const& a13,float_e4m3_t const& a14, float_e4m3_t const& a15,
        float_e4m3_t const& b0, float_e4m3_t const& b1,float_e4m3_t const& b2, float_e4m3_t const& b3,
        float_e4m3_t const& b4, float_e4m3_t const& b5,float_e4m3_t const& b6, float_e4m3_t const& b7,
        float_e4m3_t const& b8, float_e4m3_t const& b9,float_e4m3_t const& b10, float_e4m3_t const& b11,
        float_e4m3_t const& b12, float_e4m3_t const& b13,float_e4m3_t const& b14, float_e4m3_t const& b15,
        float const& c0, float const& c1, float const& c2, float const& c3)
    {
      #if (defined(__gfx938__)) && defined(DCU_ASM)
        v4f c;
        v4f d;
        c.x = c0;
        c.y = c1;
        c.z = c2;
        c.w = c3;
        cutlass::Array<float_e4m3_t,8> a_0;
        a_0[0] = a0; a_0[1] = a1; a_0[2] = a2; a_0[3] = a3;
        a_0[4] = a4; a_0[5] = a5; a_0[6] = a6; a_0[7] = a7;

        cutlass::Array<float_e4m3_t,8> a_1;
        a_1[0] = a8; a_1[1] = a9; a_1[2] = a10; a_1[3] = a11;
        a_1[4] = a12; a_1[5] = a13; a_1[6] = a14; a_1[7] = a15;
    
        cutlass::Array<float_e4m3_t,8> b_0;
        b_0[0] = b0;b_0[1] = b1;b_0[2] = b2;b_0[3] = b3;
        b_0[4] = b4;b_0[5] = b5;b_0[6] = b6;b_0[7] = b7;

        cutlass::Array<float_e4m3_t,8> b_1;
        b_1[0] = b8;b_1[1] = b9;b_1[2] = b10;b_1[3] = b11;
        b_1[4] = b12;b_1[5] = b13;b_1[6] = b14;b_1[7] = b15;

        intx2_t A, B,A1,B1;
        A = *(reinterpret_cast<intx2_t *>(&a_0));
        B = *(reinterpret_cast<intx2_t *>(&b_0));
        A1 = *(reinterpret_cast<intx2_t *>(&a_1));
        B1 = *(reinterpret_cast<intx2_t *>(&b_1));
        
        // #ifndef HG_ROCM
        d = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A, B, c, false, false);
        d = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A1, B1, d, false, false);
        // if(thread0()) {
        //   printf("A0: %f %f %f %f %f %f %f %f\n"
        //     "A1: %f %f %f %f %f %f %f %f\n"
        //     "B0: %f %f %f %f %f %f %f %f \n"
        //     "B1: %f %f %f %f %f %f %f %f \n"
        //     "C0: %f %f %f %f \n"
        //     "D1: %f %f %f %f \n",
        //     float(a0), float(a1), float(a2), float(a3),
        //     float(a4), float(a5), float(a6), float(a7),
        //     float(a8), float(a9), float(a10), float(a11),
        //     float(a12), float(a13), float(a14), float(a15),
        //     float(b0), float(b1), float(b2), float(b3),
        //     float(b4), float(b5), float(b6), float(b7),
        //     float(b8), float(b9), float(b10), float(b11),
        //     float(b12), float(b13), float(b14), float(b15),
        //     c.x, c.y, c.z, c.w, d.x, d.y, d.z, d.w
        //   );
        // }
        // #endif
        d0 = d.x;
        d1 = d.y;
        d2 = d.z;
        d3 = d.w;
      #endif
    }
 
  };




  //add 16x16x64
  struct GFX938_16x16x64_F32F8F8F32E4M3E4M3_NT_LIT
  {
    using DRegisters = float[4];
    using ARegisters = float_e4m3_t[16];
    using BRegisters = float_e4m3_t[16];
    using CRegisters = float[4];

    // Register asm fma
    CUTE_HOST_DEVICE static void
    fma(float      & d0, float      & d1, float      & d2, float      & d3, 
        float_e4m3_t const& a0, float_e4m3_t const& a1,float_e4m3_t const& a2, float_e4m3_t const& a3,
        float_e4m3_t const& a4, float_e4m3_t const& a5,float_e4m3_t const& a6, float_e4m3_t const& a7,
        float_e4m3_t const& a8, float_e4m3_t const& a9,float_e4m3_t const& a10, float_e4m3_t const& a11,
        float_e4m3_t const& a12, float_e4m3_t const& a13,float_e4m3_t const& a14, float_e4m3_t const& a15,
        float_e4m3_t const& b0, float_e4m3_t const& b1,float_e4m3_t const& b2, float_e4m3_t const& b3,
        float_e4m3_t const& b4, float_e4m3_t const& b5,float_e4m3_t const& b6, float_e4m3_t const& b7,
        float_e4m3_t const& b8, float_e4m3_t const& b9,float_e4m3_t const& b10, float_e4m3_t const& b11,
        float_e4m3_t const& b12, float_e4m3_t const& b13,float_e4m3_t const& b14, float_e4m3_t const& b15,
        float const& c0, float const& c1, float const& c2, float const& c3)
    {
      #if (defined(__gfx938__)) && defined(DCU_ASM)
        v4f c;
        v4f d;
        c.x = c0;
        c.y = c1;
        c.z = c2;
        c.w = c3;
        cutlass::Array<float_e4m3_t,8> a_0;
        a_0[0] = a0; a_0[1] = a1; a_0[2] = a2; a_0[3] = a3;
        a_0[4] = a4; a_0[5] = a5; a_0[6] = a6; a_0[7] = a7;

        cutlass::Array<float_e4m3_t,8> a_1;
        a_1[0] = a8; a_1[1] = a9; a_1[2] = a10; a_1[3] = a11;
        a_1[4] = a12; a_1[5] = a13; a_1[6] = a14; a_1[7] = a15;
    
        cutlass::Array<float_e4m3_t,8> b_0;
        b_0[0] = b0;b_0[1] = b1;b_0[2] = b2;b_0[3] = b3;
        b_0[4] = b4;b_0[5] = b5;b_0[6] = b6;b_0[7] = b7;

        cutlass::Array<float_e4m3_t,8> b_1;
        b_1[0] = b8;b_1[1] = b9;b_1[2] = b10;b_1[3] = b11;
        b_1[4] = b12;b_1[5] = b13;b_1[6] = b14;b_1[7] = b15;

        intx2_t A, B,A1,B1;
        A = *(reinterpret_cast<intx2_t *>(&a_0));
        B = *(reinterpret_cast<intx2_t *>(&b_0));
        A1 = *(reinterpret_cast<intx2_t *>(&a_1));
        B1 = *(reinterpret_cast<intx2_t *>(&b_1));
        
        // #ifndef HG_ROCM
        d = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A, B, c, true, false);
        d = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A1, B1, d, true, false);
        // if(thread0()) {
        //   printf("A0: %f %f %f %f %f %f %f %f\n"
        //     "A1: %f %f %f %f %f %f %f %f\n"
        //     "B0: %f %f %f %f %f %f %f %f \n"
        //     "B1: %f %f %f %f %f %f %f %f \n"
        //     "C0: %f %f %f %f \n"
        //     "D1: %f %f %f %f \n",
        //     float(a0), float(a1), float(a2), float(a3),
        //     float(a4), float(a5), float(a6), float(a7),
        //     float(a8), float(a9), float(a10), float(a11),
        //     float(a12), float(a13), float(a14), float(a15),
        //     float(b0), float(b1), float(b2), float(b3),
        //     float(b4), float(b5), float(b6), float(b7),
        //     float(b8), float(b9), float(b10), float(b11),
        //     float(b12), float(b13), float(b14), float(b15),
        //     c.x, c.y, c.z, c.w, d.x, d.y, d.z, d.w
        //   );
        // }
        // #endif
        d0 = d.x;
        d1 = d.y;
        d2 = d.z;
        d3 = d.w;
      #endif
    }
 
  };
    //add 16x32x32
  struct GFX938_16x32x32_F32F8F8F32E4M3E4M3_NT
  {
    using DRegisters = float[8];
    using ARegisters = float_e4m3_t[8];
    using BRegisters = float_e4m3_t[16];
    using CRegisters = float[8];

    // Register asm fma
    CUTE_HOST_DEVICE static void
    fma(float      & d0, float      & d1, float      & d2, float      & d3, 
        float      & d4, float      & d5, float      & d6, float      & d7, 
        float_e4m3_t const& a0, float_e4m3_t const& a1,float_e4m3_t const& a2, float_e4m3_t const& a3,
        float_e4m3_t const& a4, float_e4m3_t const& a5,float_e4m3_t const& a6, float_e4m3_t const& a7,
        float_e4m3_t const& b0, float_e4m3_t const& b1,float_e4m3_t const& b2, float_e4m3_t const& b3,
        float_e4m3_t const& b4, float_e4m3_t const& b5,float_e4m3_t const& b6, float_e4m3_t const& b7,
        float_e4m3_t const& b8, float_e4m3_t const& b9,float_e4m3_t const& b10, float_e4m3_t const& b11,
        float_e4m3_t const& b12, float_e4m3_t const& b13,float_e4m3_t const& b14, float_e4m3_t const& b15,
        float const& c0, float const& c1, float const& c2, float const& c3,
        float const& c4, float const& c5, float const& c6, float const& c7)
    {
      #if (defined(__gfx938__)) && defined(DCU_ASM)
      
        v4f C0,C1;
        v4f D0,D1;
        C0.x = c0;  C0.y = c1;  C0.z = c2;  C0.w = c3;
        C1.x = c4;  C1.y = c5;  C1.z = c6;  C1.w = c7;

        cutlass::Array<float_e4m3_t,8> a;
        a[0] = a0; a[1] = a1; a[2] = a2; a[3] = a3;
        a[4] = a4; a[5] = a5; a[6] = a6; a[7] = a7;
    
        cutlass::Array<float_e4m3_t,8> b_0;
        b_0[0] = b0;b_0[1] = b1;b_0[2] = b2;b_0[3] = b3;
        b_0[4] = b4;b_0[5] = b5;b_0[6] = b6;b_0[7] = b7;

        cutlass::Array<float_e4m3_t,8> b_1;
        b_1[0] = b8;b_1[1] = b9;b_1[2] = b10;b_1[3] = b11;
        b_1[4] = b12;b_1[5] = b13;b_1[6] = b14;b_1[7] = b15;

        intx2_t A, B,B1;
        A = *(reinterpret_cast<intx2_t *>(&a));
        B = *(reinterpret_cast<intx2_t *>(&b_0));
        B1 = *(reinterpret_cast<intx2_t *>(&b_1));
  
        D0 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A, B, C0, false, false);
        D1 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A, B1, C1, false, false);
      
        d0 = D0.x;  d1 = D0.y;    d2 = D0.z;  d3 = D0.w;
        d4 = D1.x;  d5 = D1.y;    d6 = D1.z;  d7 = D1.w;
       
      #endif
    }
 
  };

#if 1
  //add 16x32x32
  // struct GFX938_16x32x32_F32F8F8F32E4M3E4M3_NT_LIT
  // {
  //   using DRegisters = float[8];
  //   using ARegisters = intx2_t[1];
  //   using BRegisters = intx2_t[2];
  //   using CRegisters = float[8];

  //   // Register asm fma
  //   CUTE_HOST_DEVICE static void
  //   fma(float      & d0, float      & d1, float      & d2, float      & d3, 
  //       float      & d4, float      & d5, float      & d6, float      & d7, 
  //       intx2_t const& a0,intx2_t const& b0,intx2_t const& b1,
  //       float const& c0, float const& c1, float const& c2, float const& c3,
  //       float const& c4, float const& c5, float const& c6, float const& c7)
  //   {
  //     #if (defined(__gfx938__)) && defined(DCU_ASM)
      
  //       v4f C0,C1;
  //       v4f D0,D1;
  //       C0.x = c0;  C0.y = c1;  C0.z = c2;  C0.w = c3;
  //       C1.x = c4;  C1.y = c5;  C1.z = c6;  C1.w = c7;

        
  //       D0 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(a0, b0, C0, true, false);
  //       D1 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(a0, b1, C1, true, false);
       
  //       d0 = D0.x;  d1 = D0.y;    d2 = D0.z;  d3 = D0.w;
  //       d4 = D1.x;  d5 = D1.y;    d6 = D1.z;  d7 = D1.w;
       
  //     #endif
  //   }
 
  // };
   struct GFX938_16x32x32_F32F8F8F32E4M3E4M3_NT_LIT
  {
    using DRegisters = float[8];
    using ARegisters = float_e4m3_t[8];
    using BRegisters = intx2_t[2];
    using CRegisters = float[8];

    // Register asm fma
    CUTE_HOST_DEVICE static void
    fma(float      & d0, float      & d1, float      & d2, float      & d3, 
        float      & d4, float      & d5, float      & d6, float      & d7, 
        float_e4m3_t const& a0, float_e4m3_t const& a1,float_e4m3_t const& a2, float_e4m3_t const& a3,
        float_e4m3_t const& a4, float_e4m3_t const& a5,float_e4m3_t const& a6, float_e4m3_t const& a7,intx2_t const& b0,intx2_t const& b1,
        float const& c0, float const& c1, float const& c2, float const& c3,
        float const& c4, float const& c5, float const& c6, float const& c7)
    {
      #if (defined(__gfx938__)) && defined(DCU_ASM)
      
        v4f C0,C1;
        v4f D0,D1;
        C0.x = c0;  C0.y = c1;  C0.z = c2;  C0.w = c3;
        C1.x = c4;  C1.y = c5;  C1.z = c6;  C1.w = c7;

        cutlass::Array<float_e4m3_t,8> a;
        a[0] = a0; a[1] = a1; a[2] = a2; a[3] = a3;
        a[4] = a4; a[5] = a5; a[6] = a6; a[7] = a7;
        intx2_t A;
        A = *(reinterpret_cast<intx2_t *>(&a));

        D0 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A, b0, C0, true, false);
        D1 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A, b1, C1, true, false);
       
        d0 = D0.x;  d1 = D0.y;    d2 = D0.z;  d3 = D0.w;
        d4 = D1.x;  d5 = D1.y;    d6 = D1.z;  d7 = D1.w;
       
      #endif
    }
 
  };
#else
  //add 16x32x32
  struct GFX938_16x32x32_F32F8F8F32E4M3E4M3_NT_LIT
  {
    using DRegisters = float[8];
    using ARegisters = float_e4m3_t[8];
    using BRegisters = float_e4m3_t[16];
    using CRegisters = float[8];

    // Register asm fma
    CUTE_HOST_DEVICE static void
    fma(float      & d0, float      & d1, float      & d2, float      & d3, 
        float      & d4, float      & d5, float      & d6, float      & d7, 
        float_e4m3_t const& a0, float_e4m3_t const& a1,float_e4m3_t const& a2, float_e4m3_t const& a3,
        float_e4m3_t const& a4, float_e4m3_t const& a5,float_e4m3_t const& a6, float_e4m3_t const& a7,
        float_e4m3_t const& b0, float_e4m3_t const& b1,float_e4m3_t const& b2, float_e4m3_t const& b3,
        float_e4m3_t const& b4, float_e4m3_t const& b5,float_e4m3_t const& b6, float_e4m3_t const& b7,
        float_e4m3_t const& b8, float_e4m3_t const& b9,float_e4m3_t const& b10, float_e4m3_t const& b11,
        float_e4m3_t const& b12, float_e4m3_t const& b13,float_e4m3_t const& b14, float_e4m3_t const& b15,
        float const& c0, float const& c1, float const& c2, float const& c3,
        float const& c4, float const& c5, float const& c6, float const& c7)
    {
      #if (defined(__gfx938__)) && defined(DCU_ASM)
      
        v4f C0,C1;
        v4f D0,D1;
        C0.x = c0;  C0.y = c1;  C0.z = c2;  C0.w = c3;
        C1.x = c4;  C1.y = c5;  C1.z = c6;  C1.w = c7;

        cutlass::Array<float_e4m3_t,8> a;
        a[0] = a0; a[1] = a1; a[2] = a2; a[3] = a3;
        a[4] = a4; a[5] = a5; a[6] = a6; a[7] = a7;
    
        cutlass::Array<float_e4m3_t,8> b_0;
        b_0[0] = b0;b_0[1] = b1;b_0[2] = b2;b_0[3] = b3;
        b_0[4] = b4;b_0[5] = b5;b_0[6] = b6;b_0[7] = b7;

        cutlass::Array<float_e4m3_t,8> b_1;
        b_1[0] = b8;b_1[1] = b9;b_1[2] = b10;b_1[3] = b11;
        b_1[4] = b12;b_1[5] = b13;b_1[6] = b14;b_1[7] = b15;

        intx2_t A, B,B1;
        A = *(reinterpret_cast<intx2_t *>(&a));
        B = *(reinterpret_cast<intx2_t *>(&b_0));
        B1 = *(reinterpret_cast<intx2_t *>(&b_1));
        // #ifndef HG_ROCM
        D0 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A, B, C0, true, false);
        D1 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A, B1, C1, true, false);
        // #endif
        // if(thread0()) {
        //   printf("A: %f %f %f %f %f %f %f %f\n"
        //     "B0: %f %f %f %f %f %f %f %f \n"
        //     "B1: %f %f %f %f %f %f %f %f \n"
        //     "C0: %f %f %f %f \n"
        //     "C1: %f %f %f %f \n"
        //     "D0: %f %f %f %f \n"
        //     "D1: %f %f %f %f \n",
        //     float(a0), float(a1), float(a2), float(a3),
        //     float(a4), float(a5), float(a6), float(a7),
        //     float(b0), float(b1), float(b2), float(b3),
        //     float(b4), float(b5), float(b6), float(b7),
        //     float(b8), float(b9), float(b10), float(b11),
        //     float(b12), float(b13), float(b14), float(b15),
        //     C0.x, C0.y, C0.z, C0.w, C1.x, C1.y, C1.z, C1.w,
        //     D0.x, D0.y, D0.z, D0.w, D1.x, D1.y, D1.z, D1.w
        //   );
        // }
        d0 = D0.x;  d1 = D0.y;    d2 = D0.z;  d3 = D0.w;
        d4 = D1.x;  d5 = D1.y;    d6 = D1.z;  d7 = D1.w;
       
      #endif
    }
 
  };
#endif

  struct GFX938_16x64x32_F32F8F8F32E4M3E4M3_NT
  {
    using DRegisters = float[16];
    using ARegisters = float_e4m3_t[8];
    using BRegisters = float_e4m3_t[32];
    // using ARegisters = intx2_t[1];
    // using BRegisters = intx2_t[4];
    using CRegisters = float[16];

    // Register asm fma
    CUTE_HOST_DEVICE static void
    fma(float      & d0,  float      & d1,  float      & d2,  float      & d3,
        float      & d4,  float      & d5,  float      & d6,  float      & d7,
        float      & d8,  float      & d9,  float      & d10, float      & d11,
        float      & d12, float      & d13, float      & d14, float      & d15,
        float_e4m3_t const& a0, float_e4m3_t const& a1, float_e4m3_t const& a2, float_e4m3_t const& a3,
        float_e4m3_t const& a4, float_e4m3_t const& a5, float_e4m3_t const& a6, float_e4m3_t const& a7,

        float_e4m3_t const& b0,  float_e4m3_t const& b1,  float_e4m3_t const& b2,  float_e4m3_t const& b3,
        float_e4m3_t const& b4,  float_e4m3_t const& b5,  float_e4m3_t const& b6,  float_e4m3_t const& b7,
        float_e4m3_t const& b8,  float_e4m3_t const& b9,  float_e4m3_t const& b10, float_e4m3_t const& b11,
        float_e4m3_t const& b12, float_e4m3_t const& b13, float_e4m3_t const& b14, float_e4m3_t const& b15,
        float_e4m3_t const& b16, float_e4m3_t const& b17, float_e4m3_t const& b18, float_e4m3_t const& b19,
        float_e4m3_t const& b20, float_e4m3_t const& b21, float_e4m3_t const& b22, float_e4m3_t const& b23,
        float_e4m3_t const& b24, float_e4m3_t const& b25, float_e4m3_t const& b26, float_e4m3_t const& b27,
        float_e4m3_t const& b28, float_e4m3_t const& b29, float_e4m3_t const& b30, float_e4m3_t const& b31,
        // intx2_t const&    a   , 
        // intx2_t const&    b0  , intx2_t const& b1  , intx2_t const& b2  ,    intx2_t const& b3,

        float const& c0,  float const& c1,  float const& c2,  float const& c3,
        float const& c4,  float const& c5,  float const& c6,  float const& c7,
        float const& c8,  float const& c9,  float const& c10, float const& c11,
        float const& c12, float const& c13, float const& c14, float const& c15)
    {
  #if (defined(__gfx938__)) && defined(DCU_ASM)

      v4f C0, C1, C2, C3;
      v4f D0, D1, D2, D3;

      C0.x = c0;  C0.y = c4;  C0.z = c8;  C0.w = c12;
      C1.x = c1;  C1.y = c5;  C1.z = c9;  C1.w = c13;
      C2.x = c2;  C2.y = c6;  C2.z = c10; C2.w = c14;
      C3.x = c3;  C3.y = c7;  C3.z = c11; C3.w = c15;

      // Pack A (8) into cutlass::Array and then reinterpret as intx2_t for intrinsic
      cutlass::Array<float_e4m3_t,8> a;
      a[0] = a0; a[1] = a1; a[2] = a2; a[3] = a3;
      a[4] = a4; a[5] = a5; a[6] = a6; a[7] = a7;

      // // Pack B into four groups of 8 each
      cutlass::Array<float_e4m3_t,8> b_0;
      b_0[0] = b0;  b_0[1] = b1;  b_0[2] = b2;  b_0[3] = b3;
      b_0[4] = b4;  b_0[5] = b5;  b_0[6] = b6;  b_0[7] = b7;

      cutlass::Array<float_e4m3_t,8> b_1;
      b_1[0] = b8;  b_1[1] = b9;  b_1[2] = b10; b_1[3] = b11;
      b_1[4] = b12; b_1[5] = b13; b_1[6] = b14; b_1[7] = b15;

      cutlass::Array<float_e4m3_t,8> b_2;
      b_2[0] = b16; b_2[1] = b17; b_2[2] = b18; b_2[3] = b19;
      b_2[4] = b20; b_2[5] = b21; b_2[6] = b22; b_2[7] = b23;

      cutlass::Array<float_e4m3_t,8> b_3;
      b_3[0] = b24; b_3[1] = b25; b_3[2] = b26; b_3[3] = b27;
      b_3[4] = b28; b_3[5] = b29; b_3[6] = b30; b_3[7] = b31;

      intx2_t A_pack =  *(reinterpret_cast<const intx2_t*>(&a));
      intx2_t B0_pack = *(reinterpret_cast<const intx2_t*>(&b_0));
      intx2_t B1_pack = *(reinterpret_cast<const intx2_t*>(&b_1));
      intx2_t B2_pack = *(reinterpret_cast<const intx2_t*>(&b_2));
      intx2_t B3_pack = *(reinterpret_cast<const intx2_t*>(&b_3));

      D0 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_pack, B0_pack, C0, false, false);
      D1 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_pack, B1_pack, C1, false, false);
      D2 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_pack, B2_pack, C2, false, false);
      D3 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_pack, B3_pack, C3, false, false);

      d0  = D0.x;  d1  = D1.x;  d2  = D2.x;  d3  = D3.x;
      d4  = D0.y;  d5  = D1.y;  d6  = D2.y;  d7  = D3.y;
      d8  = D0.z;  d9  = D1.z;  d10 = D2.z;  d11 = D3.z;
      d12 = D0.w;  d13 = D1.w;  d14 = D2.w;  d15 = D3.w;

  #endif
    }
  };

   struct GFX938_16x64x32_F32BF8BF8F32E5M2E5M2_NT
  {
    using DRegisters = float[16];
    using ARegisters = float_e5m2_t[8];
    using BRegisters = float_e5m2_t[32];
    // using ARegisters = intx2_t[1];
    // using BRegisters = intx2_t[4];
    using CRegisters = float[16];

    // Register asm fma
    CUTE_HOST_DEVICE static void
    fma(float      & d0,  float      & d1,  float      & d2,  float      & d3,
        float      & d4,  float      & d5,  float      & d6,  float      & d7,
        float      & d8,  float      & d9,  float      & d10, float      & d11,
        float      & d12, float      & d13, float      & d14, float      & d15,
        float_e5m2_t const& a0, float_e5m2_t const& a1, float_e5m2_t const& a2, float_e5m2_t const& a3,
        float_e5m2_t const& a4, float_e5m2_t const& a5, float_e5m2_t const& a6, float_e5m2_t const& a7,

        float_e5m2_t const& b0,  float_e5m2_t const& b1,  float_e5m2_t const& b2,  float_e5m2_t const& b3,
        float_e5m2_t const& b4,  float_e5m2_t const& b5,  float_e5m2_t const& b6,  float_e5m2_t const& b7,
        float_e5m2_t const& b8,  float_e5m2_t const& b9,  float_e5m2_t const& b10, float_e5m2_t const& b11,
        float_e5m2_t const& b12, float_e5m2_t const& b13, float_e5m2_t const& b14, float_e5m2_t const& b15,
        float_e5m2_t const& b16, float_e5m2_t const& b17, float_e5m2_t const& b18, float_e5m2_t const& b19,
        float_e5m2_t const& b20, float_e5m2_t const& b21, float_e5m2_t const& b22, float_e5m2_t const& b23,
        float_e5m2_t const& b24, float_e5m2_t const& b25, float_e5m2_t const& b26, float_e5m2_t const& b27,
        float_e5m2_t const& b28, float_e5m2_t const& b29, float_e5m2_t const& b30, float_e5m2_t const& b31,
        // intx2_t const&    a   , 
        // intx2_t const&    b0  , intx2_t const& b1  , intx2_t const& b2  ,    intx2_t const& b3,

        float const& c0,  float const& c1,  float const& c2,  float const& c3,
        float const& c4,  float const& c5,  float const& c6,  float const& c7,
        float const& c8,  float const& c9,  float const& c10, float const& c11,
        float const& c12, float const& c13, float const& c14, float const& c15)
    {
  #if (defined(__gfx938__)) && defined(DCU_ASM)

      v4f C0, C1, C2, C3;
      v4f D0, D1, D2, D3;

      C0.x = c0;  C0.y = c4;  C0.z = c8;  C0.w = c12;
      C1.x = c1;  C1.y = c5;  C1.z = c9;  C1.w = c13;
      C2.x = c2;  C2.y = c6;  C2.z = c10; C2.w = c14;
      C3.x = c3;  C3.y = c7;  C3.z = c11; C3.w = c15;

      // Pack A (8) into cutlass::Array and then reinterpret as intx2_t for intrinsic
      cutlass::Array<float_e5m2_t,8> a;
      a[0] = a0; a[1] = a1; a[2] = a2; a[3] = a3;
      a[4] = a4; a[5] = a5; a[6] = a6; a[7] = a7;

      // // Pack B into four groups of 8 each
      cutlass::Array<float_e5m2_t,8> b_0;
      b_0[0] = b0;  b_0[1] = b1;  b_0[2] = b2;  b_0[3] = b3;
      b_0[4] = b4;  b_0[5] = b5;  b_0[6] = b6;  b_0[7] = b7;

      cutlass::Array<float_e5m2_t,8> b_1;
      b_1[0] = b8;  b_1[1] = b9;  b_1[2] = b10; b_1[3] = b11;
      b_1[4] = b12; b_1[5] = b13; b_1[6] = b14; b_1[7] = b15;

      cutlass::Array<float_e5m2_t,8> b_2;
      b_2[0] = b16; b_2[1] = b17; b_2[2] = b18; b_2[3] = b19;
      b_2[4] = b20; b_2[5] = b21; b_2[6] = b22; b_2[7] = b23;

      cutlass::Array<float_e5m2_t,8> b_3;
      b_3[0] = b24; b_3[1] = b25; b_3[2] = b26; b_3[3] = b27;
      b_3[4] = b28; b_3[5] = b29; b_3[6] = b30; b_3[7] = b31;

      intx2_t A_pack =  *(reinterpret_cast<const intx2_t*>(&a));
      intx2_t B0_pack = *(reinterpret_cast<const intx2_t*>(&b_0));
      intx2_t B1_pack = *(reinterpret_cast<const intx2_t*>(&b_1));
      intx2_t B2_pack = *(reinterpret_cast<const intx2_t*>(&b_2));
      intx2_t B3_pack = *(reinterpret_cast<const intx2_t*>(&b_3));

      D0 = __builtin_hcu_mmac_f32_16x16x32_bf8_bf8_lit_lts(A_pack, B0_pack, C0, false, false);
      D1 = __builtin_hcu_mmac_f32_16x16x32_bf8_bf8_lit_lts(A_pack, B1_pack, C1, false, false);
      D2 = __builtin_hcu_mmac_f32_16x16x32_bf8_bf8_lit_lts(A_pack, B2_pack, C2, false, false);
      D3 = __builtin_hcu_mmac_f32_16x16x32_bf8_bf8_lit_lts(A_pack, B3_pack, C3, false, false);

      d0  = D0.x;  d1  = D1.x;  d2  = D2.x;  d3  = D3.x;
      d4  = D0.y;  d5  = D1.y;  d6  = D2.y;  d7  = D3.y;
      d8  = D0.z;  d9  = D1.z;  d10 = D2.z;  d11 = D3.z;
      d12 = D0.w;  d13 = D1.w;  d14 = D2.w;  d15 = D3.w;

  #endif
    }
  };

struct GFX938_16x64x64_F32F8F8F32E4M3E4M3_NT
  {
    using DRegisters = float[16];
    using ARegisters = float_e4m3_t[16];   
    using BRegisters = float_e4m3_t[64];   
    using CRegisters = float[16];

    CUTE_HOST_DEVICE static void
    fma(float      & d0,  float      & d1,  float      & d2,  float      & d3,
        float      & d4,  float      & d5,  float      & d6,  float      & d7,
        float      & d8,  float      & d9,  float      & d10, float      & d11,
        float      & d12, float      & d13, float      & d14, float      & d15,
        // A: 16 inputs (split into low 8 and high 8)
        float_e4m3_t const& a0,  float_e4m3_t const& a1,  float_e4m3_t const& a2,  float_e4m3_t const& a3,
        float_e4m3_t const& a4,  float_e4m3_t const& a5,  float_e4m3_t const& a6,  float_e4m3_t const& a7,
        float_e4m3_t const& a8,  float_e4m3_t const& a9,  float_e4m3_t const& a10, float_e4m3_t const& a11,
        float_e4m3_t const& a12, float_e4m3_t const& a13, float_e4m3_t const& a14, float_e4m3_t const& a15,

        // B: 64 inputs (we'll group them into 8 groups of 8: b0..b7 (low32), b32..b39..b63 (high32))
        float_e4m3_t const& b0,  float_e4m3_t const& b1,  float_e4m3_t const& b2,  float_e4m3_t const& b3,
        float_e4m3_t const& b4,  float_e4m3_t const& b5,  float_e4m3_t const& b6,  float_e4m3_t const& b7,
        float_e4m3_t const& b8,  float_e4m3_t const& b9,  float_e4m3_t const& b10, float_e4m3_t const& b11,
        float_e4m3_t const& b12, float_e4m3_t const& b13, float_e4m3_t const& b14, float_e4m3_t const& b15,
        float_e4m3_t const& b16, float_e4m3_t const& b17, float_e4m3_t const& b18, float_e4m3_t const& b19,
        float_e4m3_t const& b20, float_e4m3_t const& b21, float_e4m3_t const& b22, float_e4m3_t const& b23,
        float_e4m3_t const& b24, float_e4m3_t const& b25, float_e4m3_t const& b26, float_e4m3_t const& b27,
        float_e4m3_t const& b28, float_e4m3_t const& b29, float_e4m3_t const& b30, float_e4m3_t const& b31,

        float_e4m3_t const& b32, float_e4m3_t const& b33, float_e4m3_t const& b34, float_e4m3_t const& b35,
        float_e4m3_t const& b36, float_e4m3_t const& b37, float_e4m3_t const& b38, float_e4m3_t const& b39,
        float_e4m3_t const& b40, float_e4m3_t const& b41, float_e4m3_t const& b42, float_e4m3_t const& b43,
        float_e4m3_t const& b44, float_e4m3_t const& b45, float_e4m3_t const& b46, float_e4m3_t const& b47,
        float_e4m3_t const& b48, float_e4m3_t const& b49, float_e4m3_t const& b50, float_e4m3_t const& b51,
        float_e4m3_t const& b52, float_e4m3_t const& b53, float_e4m3_t const& b54, float_e4m3_t const& b55,
        float_e4m3_t const& b56, float_e4m3_t const& b57, float_e4m3_t const& b58, float_e4m3_t const& b59,
        float_e4m3_t const& b60, float_e4m3_t const& b61, float_e4m3_t const& b62, float_e4m3_t const& b63,

        // C (initial accumulators)
        float const& c0,  float const& c1,  float const& c2,  float const& c3,
        float const& c4,  float const& c5,  float const& c6,  float const& c7,
        float const& c8,  float const& c9,  float const& c10, float const& c11,
        float const& c12, float const& c13, float const& c14, float const& c15)
    {
    #if (defined(__gfx938__)) && defined(DCU_ASM)

      v4f C0, C1, C2, C3;
      v4f D0, D1, D2, D3;

      C0.x = c0;  C0.y = c4;  C0.z = c8;  C0.w = c12;
      C1.x = c1;  C1.y = c5;  C1.z = c9;  C1.w = c13;
      C2.x = c2;  C2.y = c6;  C2.z = c10; C2.w = c14;
      C3.x = c3;  C3.y = c7;  C3.z = c11; C3.w = c15;

      cutlass::Array<float_e4m3_t,8> a_low;
      a_low[0] = a0;  a_low[1] = a1;  a_low[2] = a2;  a_low[3] = a3;
      a_low[4] = a4;  a_low[5] = a5;  a_low[6] = a6;  a_low[7] = a7;

      cutlass::Array<float_e4m3_t,8> a_high;
      a_high[0] = a8;  a_high[1] = a9;  a_high[2] = a10; a_high[3] = a11;
      a_high[4] = a12; a_high[5] = a13; a_high[6] = a14; a_high[7] = a15;

      intx2_t A_low_pack  = *(reinterpret_cast<intx2_t*>(&a_low));
      intx2_t A_high_pack = *(reinterpret_cast<intx2_t*>(&a_high));
     
      cutlass::Array<float_e4m3_t,8> b0_pack_arr;
      b0_pack_arr[0] = b0;  b0_pack_arr[1] = b1;  b0_pack_arr[2] = b2;  b0_pack_arr[3] = b3;
      b0_pack_arr[4] = b4;  b0_pack_arr[5] = b5;  b0_pack_arr[6] = b6;  b0_pack_arr[7] = b7;

      cutlass::Array<float_e4m3_t,8> b1_pack_arr;
      b1_pack_arr[0] = b8;  b1_pack_arr[1] = b9;  b1_pack_arr[2] = b10; b1_pack_arr[3] = b11;
      b1_pack_arr[4] = b12; b1_pack_arr[5] = b13; b1_pack_arr[6] = b14; b1_pack_arr[7] = b15;

      cutlass::Array<float_e4m3_t,8> b2_pack_arr;
      b2_pack_arr[0] = b16; b2_pack_arr[1] = b17; b2_pack_arr[2] = b18; b2_pack_arr[3] = b19;
      b2_pack_arr[4] = b20; b2_pack_arr[5] = b21; b2_pack_arr[6] = b22; b2_pack_arr[7] = b23;

      cutlass::Array<float_e4m3_t,8> b3_pack_arr;
      b3_pack_arr[0] = b24; b3_pack_arr[1] = b25; b3_pack_arr[2] = b26; b3_pack_arr[3] = b27;
      b3_pack_arr[4] = b28; b3_pack_arr[5] = b29; b3_pack_arr[6] = b30; b3_pack_arr[7] = b31;

      cutlass::Array<float_e4m3_t,8> b4_pack_arr;
      b4_pack_arr[0] = b32; b4_pack_arr[1] = b33; b4_pack_arr[2] = b34; b4_pack_arr[3] = b35;
      b4_pack_arr[4] = b36; b4_pack_arr[5] = b37; b4_pack_arr[6] = b38; b4_pack_arr[7] = b39;

      cutlass::Array<float_e4m3_t,8> b5_pack_arr;
      b5_pack_arr[0] = b40; b5_pack_arr[1] = b41; b5_pack_arr[2] = b42; b5_pack_arr[3] = b43;
      b5_pack_arr[4] = b44; b5_pack_arr[5] = b45; b5_pack_arr[6] = b46; b5_pack_arr[7] = b47;

      cutlass::Array<float_e4m3_t,8> b6_pack_arr;
      b6_pack_arr[0] = b48; b6_pack_arr[1] = b49; b6_pack_arr[2] = b50; b6_pack_arr[3] = b51;
      b6_pack_arr[4] = b52; b6_pack_arr[5] = b53; b6_pack_arr[6] = b54; b6_pack_arr[7] = b55;

      cutlass::Array<float_e4m3_t,8> b7_pack_arr;
      b7_pack_arr[0] = b56; b7_pack_arr[1] = b57; b7_pack_arr[2] = b58; b7_pack_arr[3] = b59;
      b7_pack_arr[4] = b60; b7_pack_arr[5] = b61; b7_pack_arr[6] = b62; b7_pack_arr[7] = b63;

      intx2_t B0_pack = *(reinterpret_cast<intx2_t*>(&b0_pack_arr));
      intx2_t B1_pack = *(reinterpret_cast<intx2_t*>(&b1_pack_arr));
      intx2_t B2_pack = *(reinterpret_cast<intx2_t*>(&b2_pack_arr));
      intx2_t B3_pack = *(reinterpret_cast<intx2_t*>(&b3_pack_arr));
      intx2_t B4_pack = *(reinterpret_cast<intx2_t*>(&b4_pack_arr));
      intx2_t B5_pack = *(reinterpret_cast<intx2_t*>(&b5_pack_arr));
      intx2_t B6_pack = *(reinterpret_cast<intx2_t*>(&b6_pack_arr));
      intx2_t B7_pack = *(reinterpret_cast<intx2_t*>(&b7_pack_arr));

      D0 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_low_pack,  B0_pack, C0, false, false);
      D1 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_low_pack,  B2_pack, C1, false, false);
      D2 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_low_pack,  B4_pack, C2, false, false);
      D3 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_low_pack,  B6_pack, C3, false, false);


      D0 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_high_pack, B1_pack, D0, false, false);
      D1 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_high_pack, B3_pack, D1, false, false);
      D2 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_high_pack, B5_pack, D2, false, false);
      D3 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_high_pack, B7_pack, D3, false, false);

      d0  = D0.x;  d1  = D1.x;  d2  = D2.x;  d3  = D3.x;
      d4  = D0.y;  d5  = D1.y;  d6  = D2.y;  d7  = D3.y;
      d8  = D0.z;  d9  = D1.z;  d10 = D2.z;  d11 = D3.z;
      d12 = D0.w;  d13 = D1.w;  d14 = D2.w;  d15 = D3.w;


  #endif
    }
  }; 


#if 1

  // struct GFX938_16x64x64_F32F8F8F32E4M3E4M3_NT_LIT
  // {
  //   using DRegisters = float[16];
  //   using ARegisters = intx2_t[2];
  //   using BRegisters = intx2_t[8];
  //   using CRegisters = float[16];

  //   // Register asm fma
  //   CUTE_HOST_DEVICE static void
  //   fma(float      & d0, float      & d1, float      & d2, float      & d3, 
  //       float      & d4, float      & d5, float      & d6, float      & d7, 
  //       float      & d8, float      & d9, float      & d10, float     & d11, 
  //       float      & d12, float     & d13, float     & d14, float     & d15, 
  //       intx2_t  const& a0, intx2_t  const& a1,intx2_t  const& b0, intx2_t  const& b1,
  //       intx2_t  const& b2, intx2_t  const& b3,intx2_t  const& b4, intx2_t  const& b5,
  //       intx2_t  const& b6, intx2_t  const& b7,
  //       float       const& c0, float       const&c1, float       const& c2, float       const& c3, 
  //       float       const&c4, float       const& c5, float       const& c6, float       const& c7, 
  //       float       const&c8, float       const& c9, float       const& c10, float      const& c11, 
  //       float       const&c12, float      const& c13, float      const& c14, float      const& c15 )
  //   {

  //       #if (defined(__gfx938__)) && defined(DCU_ASM)

  //         v4f C0,C1,C2,C3;
  //         v4f D0,D1,D2,D3;

  //         C0.x=c0 ;  C1.x=c1;     C0.y=c2 ;   C1.y= c3; 
  //         C0.z=c4;   C1.z=c5 ;    C0.w=c6;    C1.w=c7;
  //         C2.x=c8;   C3.x=c9;     C2.y=c10 ;   C3.y=c11; 
  //         C2.z=c12;  C3.z=c13;    C2.w=c14 ;   C3.w=c15;

  //         D0 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(a0, b0, C0, true, false);
  //         D1 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(a0, b2, C1, true, false);
  //         D2 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(a0, b4, C2, true, false);
  //         D3 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(a0, b6, C3, true, false);

    
  //         D0 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(a1, b1,  D0, true, false);
  //         D1 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(a1, b3,  D1, true, false);
  //         D2 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(a1, b5, D2, true, false);
  //         D3 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(a1, b7, D3, true, false);

  //         d0 = D0.x;  d1 = D1.x;     d2 = D0.y;  d3 = D1.y; 
  //         d4 = D0.z;  d5 = D1.z;     d6 = D0.w;  d7 = D1.w;

  //         d8 = D2.x;  d9 = D3.x;     d10 = D2.y;  d11 = D3.y; 
  //         d12 = D2.z; d13 = D3.z;    d14 = D2.w;  d15 = D3.w;

  //       #endif

  //   }
  // };

 struct GFX938_16x64x64_F32F8F8F32E4M3E4M3_NT_LIT
  {
    using DRegisters = float[16];
    using ARegisters = float[4];
    using BRegisters = intx2_t[8];
    using CRegisters = float[16];

    // Register asm fma
    CUTE_HOST_DEVICE static void
    fma(float      & d0, float      & d1, float      & d2, float      & d3, 
        float      & d4, float      & d5, float      & d6, float      & d7, 
        float      & d8, float      & d9, float      & d10, float     & d11, 
        float      & d12, float     & d13, float     & d14, float     & d15, 
        float const& a0, float const& a1,float const& a2, float const& a3,
        intx2_t  const& b0, intx2_t  const& b1,intx2_t  const& b2, intx2_t  const& b3,
        intx2_t  const& b4, intx2_t  const& b5,intx2_t  const& b6, intx2_t  const& b7,
        float       const& c0, float       const&c1, float       const& c2, float       const& c3, 
        float       const&c4, float       const& c5, float       const& c6, float       const& c7, 
        float       const&c8, float       const& c9, float       const& c10, float      const& c11, 
        float       const&c12, float      const& c13, float      const& c14, float      const& c15 )
    {

        #if (defined(__gfx938__)) && defined(DCU_ASM)

          v4f C0,C1,C2,C3;
          v4f D0,D1,D2,D3;

          C0.x=c0 ;  C1.x=c1;     C0.y=c2 ;   C1.y= c3; 
          C0.z=c4;   C1.z=c5 ;    C0.w=c6;    C1.w=c7;
          C2.x=c8;   C3.x=c9;     C2.y=c10 ;   C3.y=c11; 
          C2.z=c12;  C3.z=c13;    C2.w=c14 ;   C3.w=c15;

          cutlass::Array<float,4> A0,A1;

          A0[0] = a0; A0[1] = a1; 
          A1[0] = a2; A1[1] = a3; 


          intx2_t A_0, A_1;
          A_0 = *(reinterpret_cast<intx2_t *>(&A0));
          A_1 = *(reinterpret_cast<intx2_t *>(&A1));

          D0 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_0, b0, C0, true, false);
          D1 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_0, b2, C1, true, false);
          D2 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_0, b4, C2, true, false);
          D3 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_0, b6, C3, true, false);

    
          D0 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_1, b1,  D0, true, false);
          D1 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_1, b3,  D1, true, false);
          D2 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_1, b5, D2, true, false);
          D3 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_1, b7, D3, true, false);
        
          d0 = D0.x;  d1 = D1.x;     d2 = D0.y;  d3 = D1.y; 
          d4 = D0.z;  d5 = D1.z;     d6 = D0.w;  d7 = D1.w;

          d8 = D2.x;  d9 = D3.x;     d10 = D2.y;  d11 = D3.y; 
          d12 = D2.z; d13 = D3.z;    d14 = D2.w;  d15 = D3.w;
          
        #endif

    }
  };

   struct GFX938_16x64x64_F32BF8BF8F32E5M2E5M2_NT_LIT
  {
    using DRegisters = float[16];
    using ARegisters = float[4];
    using BRegisters = intx2_t[8];
    using CRegisters = float[16];

    // Register asm fma
    CUTE_HOST_DEVICE static void
    fma(float      & d0, float      & d1, float      & d2, float      & d3, 
        float      & d4, float      & d5, float      & d6, float      & d7, 
        float      & d8, float      & d9, float      & d10, float     & d11, 
        float      & d12, float     & d13, float     & d14, float     & d15, 
        float const& a0, float const& a1,float const& a2, float const& a3,
        intx2_t  const& b0, intx2_t  const& b1,intx2_t  const& b2, intx2_t  const& b3,
        intx2_t  const& b4, intx2_t  const& b5,intx2_t  const& b6, intx2_t  const& b7,
        float       const& c0, float       const&c1, float       const& c2, float       const& c3, 
        float       const&c4, float       const& c5, float       const& c6, float       const& c7, 
        float       const&c8, float       const& c9, float       const& c10, float      const& c11, 
        float       const&c12, float      const& c13, float      const& c14, float      const& c15 )
    {

        #if (defined(__gfx938__)) && defined(DCU_ASM)

          v4f C0,C1,C2,C3;
          v4f D0,D1,D2,D3;

          C0.x=c0 ;  C1.x=c1;     C0.y=c2 ;   C1.y= c3; 
          C0.z=c4;   C1.z=c5 ;    C0.w=c6;    C1.w=c7;
          C2.x=c8;   C3.x=c9;     C2.y=c10 ;   C3.y=c11; 
          C2.z=c12;  C3.z=c13;    C2.w=c14 ;   C3.w=c15;

          cutlass::Array<float,4> A0,A1;

          A0[0] = a0; A0[1] = a1; 
          A1[0] = a2; A1[1] = a3; 


          intx2_t A_0, A_1;
          A_0 = *(reinterpret_cast<intx2_t *>(&A0));
          A_1 = *(reinterpret_cast<intx2_t *>(&A1));

          D0 = __builtin_hcu_mmac_f32_16x16x32_bf8_bf8_lit_lts(A_0, b0, C0, true, false);
          D1 = __builtin_hcu_mmac_f32_16x16x32_bf8_bf8_lit_lts(A_0, b2, C1, true, false);
          D2 = __builtin_hcu_mmac_f32_16x16x32_bf8_bf8_lit_lts(A_0, b4, C2, true, false);
          D3 = __builtin_hcu_mmac_f32_16x16x32_bf8_bf8_lit_lts(A_0, b6, C3, true, false);

    
          D0 = __builtin_hcu_mmac_f32_16x16x32_bf8_bf8_lit_lts(A_1, b1,  D0, true, false);
          D1 = __builtin_hcu_mmac_f32_16x16x32_bf8_bf8_lit_lts(A_1, b3,  D1, true, false);
          D2 = __builtin_hcu_mmac_f32_16x16x32_bf8_bf8_lit_lts(A_1, b5, D2, true, false);
          D3 = __builtin_hcu_mmac_f32_16x16x32_bf8_bf8_lit_lts(A_1, b7, D3, true, false);
        
          d0 = D0.x;  d1 = D1.x;     d2 = D0.y;  d3 = D1.y; 
          d4 = D0.z;  d5 = D1.z;     d6 = D0.w;  d7 = D1.w;

          d8 = D2.x;  d9 = D3.x;     d10 = D2.y;  d11 = D3.y; 
          d12 = D2.z; d13 = D3.z;    d14 = D2.w;  d15 = D3.w;
          
        #endif

    }
  };

 
#else
////////////////////////////v_mmac_16x64x64 concatenate by 4x16x32x16/////////////////////////////////////////////
  struct GFX938_16x64x64_F32F8F8F32E4M3E4M3_NT_LIT
  {
    using DRegisters = float[16];
    using ARegisters = float_e4m3_t[16];
    using BRegisters = float_e4m3_t[64];
    using CRegisters = float[16];

    // Register asm fma
    CUTE_HOST_DEVICE static void
    fma(float      & d0, float      & d1, float      & d2, float      & d3, 
        float      & d4, float      & d5, float      & d6, float      & d7, 
        float      & d8, float      & d9, float      & d10, float     & d11, 
        float      & d12, float     & d13, float     & d14, float     & d15, 
        float_e4m3_t const& a0, float_e4m3_t const& a1,float_e4m3_t const& a2, float_e4m3_t const& a3,
        float_e4m3_t const& a4, float_e4m3_t const& a5,float_e4m3_t const& a6, float_e4m3_t const& a7,
        float_e4m3_t const& a8, float_e4m3_t const& a9,float_e4m3_t const& a10, float_e4m3_t const& a11,
        float_e4m3_t const& a12, float_e4m3_t const& a13,float_e4m3_t const& a14, float_e4m3_t const& a15,
        float_e4m3_t const& b0, float_e4m3_t const& b1,float_e4m3_t const& b2, float_e4m3_t const& b3,
        float_e4m3_t const& b4, float_e4m3_t const& b5,float_e4m3_t const& b6, float_e4m3_t const& b7,
        float_e4m3_t const& b8, float_e4m3_t const& b9,float_e4m3_t const& b10, float_e4m3_t const& b11,
        float_e4m3_t const& b12, float_e4m3_t const& b13,float_e4m3_t const& b14, float_e4m3_t const& b15,
        float_e4m3_t const& b16, float_e4m3_t const& b17,float_e4m3_t const& b18, float_e4m3_t const& b19,
        float_e4m3_t const& b20, float_e4m3_t const& b21,float_e4m3_t const& b22, float_e4m3_t const& b23,
        float_e4m3_t const& b24, float_e4m3_t const& b25,float_e4m3_t const& b26, float_e4m3_t const& b27,
        float_e4m3_t const& b28, float_e4m3_t const& b29,float_e4m3_t const& b30, float_e4m3_t const& b31,
        float_e4m3_t const& b32, float_e4m3_t const& b33,float_e4m3_t const& b34, float_e4m3_t const& b35,
        float_e4m3_t const& b36, float_e4m3_t const& b37,float_e4m3_t const& b38, float_e4m3_t const& b39,
        float_e4m3_t const& b40, float_e4m3_t const& b41,float_e4m3_t const& b42, float_e4m3_t const& b43,
        float_e4m3_t const& b44, float_e4m3_t const& b45,float_e4m3_t const& b46, float_e4m3_t const& b47,
        float_e4m3_t const& b48, float_e4m3_t const& b49,float_e4m3_t const& b50, float_e4m3_t const& b51,
        float_e4m3_t const& b52, float_e4m3_t const& b53,float_e4m3_t const& b54, float_e4m3_t const& b55,
        float_e4m3_t const& b56, float_e4m3_t const& b57,float_e4m3_t const& b58, float_e4m3_t const& b59,
        float_e4m3_t const& b60, float_e4m3_t const& b61,float_e4m3_t const& b62, float_e4m3_t const& b63,
        float       const& c0, float       const&c1, float       const& c2, float       const& c3, 
        float       const&c4, float       const& c5, float       const& c6, float       const& c7, 
        float       const&c8, float       const& c9, float       const& c10, float      const& c11, 
        float       const&c12, float      const& c13, float      const& c14, float      const& c15 )
    {

        #if (defined(__gfx938__)) && defined(DCU_ASM)

          v4f C0,C1,C2,C3;
          v4f D0,D1,D2,D3;

          C0.x=c0 ;  C1.x=c1;     C0.y=c2 ;   C1.y= c3; 
          C0.z=c4;   C1.z=c5 ;    C0.w=c6;    C1.w=c7;
          C2.x=c8;   C3.x=c9;     C2.y=c10 ;   C3.y=c11; 
          C2.z=c12;  C3.z=c13;    C2.w=c14 ;   C3.w=c15;

          cutlass::Array<float_e4m3_t,8> A0,A1,B0,B1,B2,B3,B4,B5,B6,B7;

          A0[0] = a0; A0[1] = a1; A0[2] = a2; A0[3] = a3;
          A0[4] = a4; A0[5] = a5; A0[6] = a6; A0[7] = a7;

          A1[0] = a8; A1[1] = a9; A1[2] = a10; A1[3] = a11;
          A1[4] = a12; A1[5] = a13; A1[6] = a14; A1[7] = a15;

          B0[0] = b0;B0[1] = b1;B0[2] = b2;B0[3] = b3;
          B0[4] = b4;B0[5] = b5;B0[6] = b6;B0[7] = b7;

        
          B1[0] = b16;B1[1] = b17;B1[2] = b18;B1[3] = b19;
          B1[4] = b20;B1[5] = b21;B1[6] = b22;B1[7] = b23;
      
          B2[0] = b32;B2[1] = b33;B2[2] = b34;B2[3] = b35;
          B2[4] = b36;B2[5] = b37;B2[6] = b38;B2[7] = b39;

          B3[0] = b48;B3[1] = b49;B3[2] = b50;B3[3] = b51;
          B3[4] = b52;B3[5] = b53;B3[6] = b54;B3[7] = b55;

          B4[0] = b8;B4[1] = b9;B4[2] = b10;B4[3] = b11;
          B4[4] = b12;B4[5] = b13;B4[6] = b14;B4[7] = b15;

        
          B5[0] = b24;B5[1] = b25;B5[2] = b26;B5[3] = b27;
          B5[4] = b28;B5[5] = b29;B5[6] = b30;B5[7] = b31;

        
          B6[0] = b40;B6[1] = b41;B6[2] = b42;B6[3] = b43;
          B6[4] = b44;B6[5] = b45;B6[6] = b46;B6[7] = b47;


          B7[0] = b56;B7[1] = b57;B7[2] = b58;B7[3] = b59;
          B7[4] = b60;B7[5] = b61;B7[6] = b62;B7[7] = b63;

          intx2_t A_0, A_1,B_0,B_1,B_2,B_3,B_4,B_5,B_6,B_7;
          A_0 = *(reinterpret_cast<intx2_t *>(&A0));
          A_1 = *(reinterpret_cast<intx2_t *>(&A1));
          B_0 = *(reinterpret_cast<intx2_t *>(&B0));
          B_1 = *(reinterpret_cast<intx2_t *>(&B1));
          B_2 = *(reinterpret_cast<intx2_t *>(&B2));
          B_3 = *(reinterpret_cast<intx2_t *>(&B3));
          B_4 = *(reinterpret_cast<intx2_t *>(&B4));
          B_5 = *(reinterpret_cast<intx2_t *>(&B5));
          B_6 = *(reinterpret_cast<intx2_t *>(&B6));
          B_7 = *(reinterpret_cast<intx2_t *>(&B7));


          D0 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_0, B_0, C0, true, false);
          D1 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_0, B_1, C1, true, false);
          D2 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_0, B_2, C2, true, false);
          D3 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_0, B_3, C3, true, false);

    
          D0 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_1, B_4,  D0, true, false);
          D1 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_1, B_5,  D1, true, false);
          D2 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_1, B_6, D2, true, false);
          D3 = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A_1, B_7, D3, true, false);
        
          d0 = D0.x;  d1 = D1.x;     d2 = D0.y;  d3 = D1.y; 
          d4 = D0.z;  d5 = D1.z;     d6 = D0.w;  d7 = D1.w;

          d8 = D2.x;  d9 = D3.x;     d10 = D2.y;  d11 = D3.y; 
          d12 = D2.z; d13 = D3.z;    d14 = D2.w;  d15 = D3.w;
        #endif

    }
  };
#endif

  


  
  struct GFX938_16x16x64_F32F8F8F32E4M3E4M3_NN_LIT : GFX938_16x16x64_F32F8F8F32E4M3E4M3_NT_LIT {};
  struct GFX938_16x64x64_F32F8F8F32E4M3E4M3_NT_LIT_BLayout : GFX938_16x64x64_F32F8F8F32E4M3E4M3_NT_LIT {};
  struct GFX938_16x64x64_F32F8F8F32E4M3E4M3_NT_BLayout : GFX938_16x64x64_F32F8F8F32E4M3E4M3_NT {};
  struct GFX938_16x64x32_F32F8F8F32E4M3E4M3_NN : GFX938_16x64x32_F32F8F8F32E4M3E4M3_NT {};
  struct GFX938_16x64x32_F32F8F8F32E4M3E4M3_NN_Blayout : GFX938_16x64x32_F32F8F8F32E4M3E4M3_NT {};
  struct GFX938_16x64x32_F32F8F8F32E4M3E4M3_NT_BLayout : GFX938_16x64x32_F32F8F8F32E4M3E4M3_NT {};

  struct GFX938_16x64x32_F32BF8BF8F32E5M2E5M2_NN : GFX938_16x64x32_F32BF8BF8F32E5M2E5M2_NT {};
  struct GFX938_16x64x64_F32BF8BF8F32E5M2E5M2_NT_LIT_BLayout : GFX938_16x64x64_F32BF8BF8F32E5M2E5M2_NT_LIT {};
} // end namespace cute
