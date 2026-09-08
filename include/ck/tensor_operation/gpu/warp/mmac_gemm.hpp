// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck/utility/common_header.hpp"
#include "ck/utility/hcu_mmac.hpp"
#include "ck/utility/math.hpp"

namespace ck {

enum struct MmacInstr
{
    mmac_f32_16x16x4f32 = 0,
    mmac_f32_16x16x8f32,
    mmac_f32_16x16x8tf32,
    mmac_f32_16x16x16f16,
    mmac_f32_16x16x16bf16,
    mmac_f32_16x16x32f8_f8,
    mmac_f32_16x16x32f8_bf8,
    mmac_f32_16x16x32bf8_bf8,
    mmac_f32_16x16x32bf8_f8,
    mmac_i32_16x16x32i8,
    mmac_i32_16x16x32u8,
    mmac_i32_16x16x64i4,
    mmac_i32_16x16x64u4,
    mmac_16x16x4f64,
};

template <MmacInstr instr>
struct mmac_type;

template<>
struct mmac_type<MmacInstr::mmac_16x16x4f64>
{
    static constexpr index_t group_size          = 1;
    static constexpr index_t num_groups_per_blk  = 4;
    static constexpr index_t num_regs_per_blk    = 4;
    static constexpr index_t num_threads_per_blk = 16;
    static constexpr index_t wave_size           = 64;
    static constexpr index_t num_input_blks      = 4;
    static constexpr index_t num_output_blks     = 1;
    static constexpr index_t m_per_blk           = 16;
    static constexpr index_t n_per_blk           = 16;
    static constexpr index_t k_per_blk           = 1;
    static constexpr bool is_k_reduction         = true;

    template <typename A, typename B, typename C>
    __device__ void run (const A& a, const B& b, C& reg_c) const
    {
        intrin_mmac_16x16x4f64(bit_cast<double>(a), bit_cast<double>(b), reg_c);
    }
};

template <>
struct mmac_type<MmacInstr::mmac_f32_16x16x4f32>
{
    static constexpr index_t group_size          = 1;
    static constexpr index_t num_groups_per_blk  = 4;
    static constexpr index_t num_regs_per_blk    = 4;
    static constexpr index_t num_threads_per_blk = 16;
    static constexpr index_t wave_size           = 64;
    static constexpr index_t num_input_blks      = 4;
    static constexpr index_t num_output_blks     = 1;
    static constexpr index_t m_per_blk           = 16;
    static constexpr index_t n_per_blk           = 16;
    static constexpr index_t k_per_blk           = 1;
    static constexpr bool is_k_reduction         = true;

    template <typename A, typename B, typename C>
    __device__ void run(const A& a, const B& b, C& reg_c) const
    {
        intrin_mmac_f32_16x16x4f32(bit_cast<float>(a), bit_cast<float>(b), reg_c);
    }
};

template <>
struct mmac_type<MmacInstr::mmac_f32_16x16x8f32>
{
    static constexpr index_t group_size          = 1;
    static constexpr index_t num_groups_per_blk  = 4;
    static constexpr index_t num_regs_per_blk    = 4;
    static constexpr index_t num_threads_per_blk = 16;
    static constexpr index_t wave_size           = 64;
    static constexpr index_t num_input_blks      = 4;
    static constexpr index_t num_output_blks     = 1;
    static constexpr index_t m_per_blk           = 16;
    static constexpr index_t n_per_blk           = 16;
    static constexpr index_t k_per_blk           = 2;
    static constexpr bool is_k_reduction         = true;

    template <typename A, typename B, typename C>
    __device__ void run(const A& a, const B& b, C& reg_c) const
    {
        intrin_mmac_f32_16x16x8f32(bit_cast<float2_t>(a), bit_cast<float2_t>(b), reg_c);
    }
};

template <>
struct mmac_type<MmacInstr::mmac_f32_16x16x8tf32>
{
    static constexpr index_t group_size          = 1;
    static constexpr index_t num_groups_per_blk  = 4;
    static constexpr index_t num_regs_per_blk    = 4;
    static constexpr index_t num_threads_per_blk = 16;
    static constexpr index_t wave_size           = 64;
    static constexpr index_t num_input_blks      = 4;
    static constexpr index_t num_output_blks     = 1;
    static constexpr index_t m_per_blk           = 16;
    static constexpr index_t n_per_blk           = 16;
    static constexpr index_t k_per_blk           = 2;
    static constexpr bool is_k_reduction         = true;

    template <typename A, typename B, typename C>
    __device__ void run(const A& a, const B& b, C& reg_c) const
    {
        intrin_mmac_f32_16x16x8tf32(bit_cast<int32x2_t>(a), bit_cast<int32x2_t>(b), reg_c);
    }
};

template <>
struct mmac_type<MmacInstr::mmac_f32_16x16x16f16>
{
    static constexpr index_t group_size          = 1;
    static constexpr index_t num_groups_per_blk  = 4;
    static constexpr index_t num_regs_per_blk    = 4;
    static constexpr index_t num_threads_per_blk = 16;
    static constexpr index_t wave_size           = 64;
    static constexpr index_t num_input_blks      = 4;
    static constexpr index_t num_output_blks     = 1;
    static constexpr index_t m_per_blk           = 16;
    static constexpr index_t n_per_blk           = 16;
    static constexpr index_t k_per_blk           = 4;
    static constexpr bool is_k_reduction         = true;

    template <typename A, typename B, typename C>
    __device__ void run(const A& a, const B& b, C& reg_c) const
    {
        intrin_mmac_f32_16x16x16f16(bit_cast<half4_t>(a), bit_cast<half4_t>(b), reg_c);
    }
};

template <>
struct mmac_type<MmacInstr::mmac_f32_16x16x16bf16>
{
    static constexpr index_t group_size          = 1;
    static constexpr index_t num_groups_per_blk  = 4;
    static constexpr index_t num_regs_per_blk    = 4;
    static constexpr index_t num_threads_per_blk = 16;
    static constexpr index_t wave_size           = 64;
    static constexpr index_t num_input_blks      = 4;
    static constexpr index_t num_output_blks     = 1;
    static constexpr index_t m_per_blk           = 16;
    static constexpr index_t n_per_blk           = 16;
    static constexpr index_t k_per_blk           = 4;
    static constexpr bool is_k_reduction         = true;

    template <typename A, typename B, typename C>
    __device__ void run(const A& a, const B& b, C& reg_c) const
    {
        intrin_mmac_f32_16x16x16bf16(bit_cast<int16x4_t>(a), bit_cast<int16x4_t>(b), reg_c);
    }
};

template <>
struct mmac_type<MmacInstr::mmac_f32_16x16x32f8_f8>
{
    static constexpr index_t group_size          = 1;
    static constexpr index_t num_groups_per_blk  = 4;
    static constexpr index_t num_regs_per_blk    = 4;
    static constexpr index_t num_threads_per_blk = 16;
    static constexpr index_t wave_size           = 64;
    static constexpr index_t num_input_blks      = 4;
    static constexpr index_t num_output_blks     = 1;
    static constexpr index_t m_per_blk           = 16;
    static constexpr index_t n_per_blk           = 16;
    static constexpr index_t k_per_blk           = 8;
    static constexpr bool is_k_reduction         = true;

    template <typename A, typename B, typename C>
    __device__ void run(const A& a, const B& b, C& reg_c) const
    {
        intrin_mmac_f32_16x16x32f8_f8(bit_cast<int32x2_t>(a), bit_cast<int32x2_t>(b), reg_c);
    }
};

template <>
struct mmac_type<MmacInstr::mmac_f32_16x16x32f8_bf8>
{
    static constexpr index_t group_size          = 1;
    static constexpr index_t num_groups_per_blk  = 4;
    static constexpr index_t num_regs_per_blk    = 4;
    static constexpr index_t num_threads_per_blk = 16;
    static constexpr index_t wave_size           = 64;
    static constexpr index_t num_input_blks      = 4;
    static constexpr index_t num_output_blks     = 1;
    static constexpr index_t m_per_blk           = 16;
    static constexpr index_t n_per_blk           = 16;
    static constexpr index_t k_per_blk           = 8;
    static constexpr bool is_k_reduction         = true;

    template <typename A, typename B, typename C>
    __device__ void run(const A& a, const B& b, C& reg_c) const
    {
        intrin_mmac_f32_16x16x32f8_bf8(bit_cast<int32x2_t>(a), bit_cast<int32x2_t>(b), reg_c);
    }
};

template <>
struct mmac_type<MmacInstr::mmac_f32_16x16x32bf8_bf8>
{
    static constexpr index_t group_size          = 1;
    static constexpr index_t num_groups_per_blk  = 4;
    static constexpr index_t num_regs_per_blk    = 4;
    static constexpr index_t num_threads_per_blk = 16;
    static constexpr index_t wave_size           = 64;
    static constexpr index_t num_input_blks      = 4;
    static constexpr index_t num_output_blks     = 1;
    static constexpr index_t m_per_blk           = 16;
    static constexpr index_t n_per_blk           = 16;
    static constexpr index_t k_per_blk           = 8;
    static constexpr bool is_k_reduction         = true;

    template <typename A, typename B, typename C>
    __device__ void run(const A& a, const B& b, C& reg_c) const
    {
        intrin_mmac_f32_16x16x32bf8_bf8(bit_cast<int32x2_t>(a), bit_cast<int32x2_t>(b), reg_c);
    }
};

template <>
struct mmac_type<MmacInstr::mmac_f32_16x16x32bf8_f8>
{
    static constexpr index_t group_size          = 1;
    static constexpr index_t num_groups_per_blk  = 4;
    static constexpr index_t num_regs_per_blk    = 4;
    static constexpr index_t num_threads_per_blk = 16;
    static constexpr index_t wave_size           = 64;
    static constexpr index_t num_input_blks      = 4;
    static constexpr index_t num_output_blks     = 1;
    static constexpr index_t m_per_blk           = 16;
    static constexpr index_t n_per_blk           = 16;
    static constexpr index_t k_per_blk           = 8;
    static constexpr bool is_k_reduction         = true;

    template <typename A, typename B, typename C>
    __device__ void run(const A& a, const B& b, C& reg_c) const
    {
        intrin_mmac_f32_16x16x32bf8_f8(bit_cast<int32x2_t>(a), bit_cast<int32x2_t>(b), reg_c);
    }
};

template <>
struct mmac_type<MmacInstr::mmac_i32_16x16x32i8>
{
    static constexpr index_t group_size          = 1;
    static constexpr index_t num_groups_per_blk  = 4;
    static constexpr index_t num_regs_per_blk    = 4;
    static constexpr index_t num_threads_per_blk = 16;
    static constexpr index_t wave_size           = 64;
    static constexpr index_t num_input_blks      = 4;
    static constexpr index_t num_output_blks     = 1;
    static constexpr index_t m_per_blk           = 16;
    static constexpr index_t n_per_blk           = 16;
    static constexpr index_t k_per_blk           = 8;
    static constexpr bool is_k_reduction         = true;

    template <typename A, typename B, typename C>
    __device__ void run(const A& a, const B& b, C& reg_c) const
    {
        intrin_mmac_i32_16x16x32i8(bit_cast<int32x2_t>(a), bit_cast<int32x2_t>(b), reg_c);
    }
};

template <>
struct mmac_type<MmacInstr::mmac_i32_16x16x32u8>
{
    static constexpr index_t group_size          = 1;
    static constexpr index_t num_groups_per_blk  = 4;
    static constexpr index_t num_regs_per_blk    = 4;
    static constexpr index_t num_threads_per_blk = 16;
    static constexpr index_t wave_size           = 64;
    static constexpr index_t num_input_blks      = 4;
    static constexpr index_t num_output_blks     = 1;
    static constexpr index_t m_per_blk           = 16;
    static constexpr index_t n_per_blk           = 16;
    static constexpr index_t k_per_blk           = 8;
    static constexpr bool is_k_reduction         = true;

    template <typename A, typename B, typename C>
    __device__ void run(const A& a, const B& b, C& reg_c) const
    {
        intrin_mmac_i32_16x16x32u8(bit_cast<int32x2_t>(a), bit_cast<int32x2_t>(b), reg_c);
    }
};

template <>
struct mmac_type<MmacInstr::mmac_i32_16x16x64i4>
{
    static constexpr index_t group_size          = 1;
    static constexpr index_t num_groups_per_blk  = 4;
    static constexpr index_t num_regs_per_blk    = 4;
    static constexpr index_t num_threads_per_blk = 16;
    static constexpr index_t wave_size           = 64;
    static constexpr index_t num_input_blks      = 4;
    static constexpr index_t num_output_blks     = 1;
    static constexpr index_t m_per_blk           = 16;
    static constexpr index_t n_per_blk           = 16;
    static constexpr index_t k_per_blk           = 8; // u8x8 <-> i4x16
    static constexpr bool is_k_reduction         = true;

    template <typename A, typename B, typename C>
    __device__ void run(const A& a, const B& b, C& reg_c) const
    {
        intrin_mmac_i32_16x16x64i4(bit_cast<int32x2_t>(a), bit_cast<int32x2_t>(b), reg_c);
    }
};

template <>
struct mmac_type<MmacInstr::mmac_i32_16x16x64u4>
{
    static constexpr index_t group_size          = 1;
    static constexpr index_t num_groups_per_blk  = 4;
    static constexpr index_t num_regs_per_blk    = 4;
    static constexpr index_t num_threads_per_blk = 16;
    static constexpr index_t wave_size           = 64;
    static constexpr index_t num_input_blks      = 4;
    static constexpr index_t num_output_blks     = 1;
    static constexpr index_t m_per_blk           = 16;
    static constexpr index_t n_per_blk           = 16;
    static constexpr index_t k_per_blk           = 8; // u8x8 <-> u4x16
    static constexpr bool is_k_reduction         = true;

    template <typename A, typename B, typename C>
    __device__ void run(const A& a, const B& b, C& reg_c) const
    {
        intrin_mmac_i32_16x16x64u4(bit_cast<int32x2_t>(a), bit_cast<int32x2_t>(b), reg_c);
    }
};

// MPerMmac, NPerMmac is always 16 for now, keep them for future use
// ADataType, BDataType and TransposeC is for mixed mmac such as bf8_f8, will add them in the future
// KPerBlock is used to distinguish mmac_f32_16x16x4f32 and mmac_f32_16x16x8f32
template <typename ADataType,
          typename BDataType,
          index_t MPerMmac,
          index_t NPerMmac,
          index_t KPerBlock,
          bool TransposeC = false>
struct MmacSelector
{
    template <typename ADataType_,
              typename BDataType_,
              index_t MPerMMAC_,
              index_t NPerMMAC_,
              index_t KPerBlock_>
    struct MmacTraits;

    template <index_t KPerBlock_>
    struct MmacTraits<double, double, 16, 16, KPerBlock_>
    {
        static constexpr auto value = MmacInstr::mmac_16x16x4f64;
    };

#if defined(__gfx926__) || defined(__gfx92a__)
    template <index_t KPerBlock_>
    struct MmacTraits<float, float, 16, 16, KPerBlock_>
    {
        static constexpr auto value = MmacInstr::mmac_f32_16x16x4f32;
    };

#else
    template <>
    struct MmacTraits<float, float, 16, 16, 4>
    {
        static constexpr auto value = MmacInstr::mmac_f32_16x16x4f32;
    };

    template <index_t KPerBlock_>
    struct MmacTraits<float, float, 16, 16, KPerBlock_>
    {
        static constexpr auto value = MmacInstr::mmac_f32_16x16x8f32;
    };
#endif

    template <index_t KPerBlock_>
    struct MmacTraits<tf32_t, tf32_t, 16, 16, KPerBlock_>
    {
        static constexpr auto value = MmacInstr::mmac_f32_16x16x8tf32;
    };

    template <index_t KPerBlock_>
    struct MmacTraits<half_t, half_t, 16, 16, KPerBlock_>
    {
        static constexpr auto value = MmacInstr::mmac_f32_16x16x16f16;
    };

    template <index_t KPerBlock_>
    struct MmacTraits<bhalf_t, bhalf_t, 16, 16, KPerBlock_>
    {
        static constexpr auto value = MmacInstr::mmac_f32_16x16x16bf16;
    };

    template <index_t KPerBlock_>
    struct MmacTraits<int8_t, int8_t, 16, 16, KPerBlock_>
    {
        static constexpr auto value = MmacInstr::mmac_i32_16x16x32i8;
    };

    template <index_t KPerBlock_>
    struct MmacTraits<uint8_t, uint8_t, 16, 16, KPerBlock_>
    {
        static constexpr auto value = MmacInstr::mmac_i32_16x16x32u8;
    };

#ifdef CK_EXPERIMENTAL_BIT_INT_EXTENSION
    template <index_t KPerBlock_>
    struct MmacTraits<fp8_t, fp8_t, 16, 16, KPerBlock_>
    {
        static constexpr auto value = MmacInstr::mmac_f32_16x16x32f8_f8;
    };

    template <index_t KPerBlock_>
    struct MmacTraits<fp8_t, bf8_t, 16, 16, KPerBlock_>
    {
        static constexpr auto value = MmacInstr::mmac_f32_16x16x32f8_bf8;
    };

    template <index_t KPerBlock_>
    struct MmacTraits<bf8_t, bf8_t, 16, 16, KPerBlock_>
    {
        static constexpr auto value = MmacInstr::mmac_f32_16x16x32bf8_bf8;
    };

    template <index_t KPerBlock_>
    struct MmacTraits<bf8_t, fp8_t, 16, 16, KPerBlock_>
    {
        static constexpr auto value = MmacInstr::mmac_f32_16x16x32bf8_f8;
    };

    template <index_t KPerBlock_>
    struct MmacTraits<int4_t, int4_t, 16, 16, KPerBlock_>
    {
        static constexpr auto value = MmacInstr::mmac_i32_16x16x64i4;
    };

    template <index_t KPerBlock_>
    struct MmacTraits<uint4_t, uint4_t, 16, 16, KPerBlock_>
    {
        static constexpr auto value = MmacInstr::mmac_i32_16x16x64u4;
    };
#endif

    __host__ __device__ static constexpr auto get_mmac()
    {
        if constexpr(TransposeC)
            return mmac_type<
                MmacTraits<BDataType, ADataType, MPerMmac, NPerMmac, KPerBlock>::value>{};
        else
            return mmac_type<
                MmacTraits<ADataType, BDataType, MPerMmac, NPerMmac, KPerBlock>::value>{};
    }

    static constexpr auto selected_mmac = get_mmac();

    __host__ __device__ constexpr MmacSelector()
    {
        static_assert(selected_mmac.m_per_blk == 16 && selected_mmac.n_per_blk == 16,
                      "m_per_blk and n_per_blk must be 16!");

        static_assert(selected_mmac.group_size * selected_mmac.num_groups_per_blk ==
                          selected_mmac.num_regs_per_blk,
                      "wrong! num_regs_per_blk");

        static_assert(selected_mmac.num_threads_per_blk == selected_mmac.n_per_blk,
                      "n_per_blk != num_threads_per_blk");

        static_assert(selected_mmac.num_regs_per_blk * selected_mmac.num_input_blks ==
                          selected_mmac.m_per_blk,
                      "m_per_blk != num_input_blks * num_regs_per_blk");

        static_assert(selected_mmac.num_output_blks == selected_mmac.num_input_blks ||
                          selected_mmac.num_output_blks == 1,
                      "incorrect num_output_blks");

        static_assert(selected_mmac.num_regs_per_blk * selected_mmac.wave_size ==
                          selected_mmac.m_per_blk * selected_mmac.n_per_blk,
                      "num_regs_per_blk incorrect");

        static_assert(selected_mmac.is_k_reduction == true, "is_k_reduction wrong!");
    }

    __host__ __device__ static constexpr index_t GetKPerMmac()
    {
        return selected_mmac.num_input_blks * selected_mmac.k_per_blk;
    }

    __host__ __device__ static constexpr index_t GetK1PerMmac() { return selected_mmac.k_per_blk; }
};

template <typename ADataType,
          typename BDataType,
          index_t MPerMmac,
          index_t NPerMmac,
          index_t KPerBlock,
          index_t KPack,
          bool TransposeC         = false,
          index_t MmmacRepeat     = 1,
          index_t NmmacRepeat     = 1,
          index_t MmmacInterleave = 1,
          index_t NmmacInterleave = 1>
struct MmacGemm
{
    static constexpr auto I0 = Number<0>{};
    static constexpr auto I1 = Number<1>{};
    static constexpr auto I2 = Number<2>{};
    static constexpr auto I3 = Number<3>{};
    static constexpr auto I4 = Number<4>{};
    static constexpr auto I5 = Number<5>{};

    using CIndex   = MultiIndex<2>;
    using CIndex4D = MultiIndex<4>;

    __device__ static constexpr index_t GetNumBlks() { return mmac_instr.num_output_blks; }

    __device__ static constexpr index_t GetNumMmac()
    {
        return MmmacRepeat * NmmacRepeat * MmmacInterleave * NmmacInterleave;
    }

    __host__ __device__ constexpr MmacGemm()
    {
        static_assert(MPerMmac == mmac_instr.m_per_blk && NPerMmac == mmac_instr.n_per_blk,
                      "MPerMmac/NPerMmac not equal to m_per_blk/n_per_blk");

        static_assert(KPack % mmac_instr.k_per_blk == 0, "KPack cannot be divided by k_per_blk");
    }

    // mmac output C
    // M2_N2 -> M2_N2_N3_N4
    template <typename CDesc_M0_N0_M1_N1_M2_N2>
    __host__ __device__ static constexpr auto
    MakeCDescriptor_M0_N0_M1_N1_M2_N2_N3_N4(const CDesc_M0_N0_M1_N1_M2_N2& c_desc_m0_n0_m1_n1_m2_n2)
    {
        const auto M0 = c_desc_m0_n0_m1_n1_m2_n2.GetLength(I0);
        const auto N0 = c_desc_m0_n0_m1_n1_m2_n2.GetLength(I1);
        const auto M1 = c_desc_m0_n0_m1_n1_m2_n2.GetLength(I2);
        const auto N1 = c_desc_m0_n0_m1_n1_m2_n2.GetLength(I3);

        return transform_tensor_descriptor(
            c_desc_m0_n0_m1_n1_m2_n2,
            make_tuple(make_pass_through_transform(M0),
                       make_pass_through_transform(N0),
                       make_pass_through_transform(M1),
                       make_pass_through_transform(N1),
                       make_pass_through_transform(Number<mmac_instr.num_threads_per_blk>{}),
                       make_unmerge_transform(make_tuple(Number<mmac_instr.num_groups_per_blk>{},
                                                         Number<mmac_instr.num_input_blks>{},
                                                         Number<mmac_instr.group_size>{}))),
            make_tuple(Sequence<0>{},
                       Sequence<1>{},
                       Sequence<2>{},
                       Sequence<3>{},
                       Sequence<4>{},
                       Sequence<5>{}),
            make_tuple(Sequence<0>{},
                       Sequence<1>{},
                       Sequence<2>{},
                       Sequence<3>{},
                       Sequence<4>{},
                       Sequence<5, 6, 7>{}));
    }

    // transposed mmac output C'
    // M2_N2 -> M2_M3_M4_N2
    template <typename CDesc_M0_N0_M1_N1_M2_N2>
    __host__ __device__ static constexpr auto
    MakeCDescriptor_M0_N0_M1_N1_M2_M3_M4_N2(const CDesc_M0_N0_M1_N1_M2_N2& c_desc_m0_n0_m1_n1_m2_n2)
    {
        const auto M0 = c_desc_m0_n0_m1_n1_m2_n2.GetLength(I0);
        const auto N0 = c_desc_m0_n0_m1_n1_m2_n2.GetLength(I1);
        const auto M1 = c_desc_m0_n0_m1_n1_m2_n2.GetLength(I2);
        const auto N1 = c_desc_m0_n0_m1_n1_m2_n2.GetLength(I3);

        return transform_tensor_descriptor(
            c_desc_m0_n0_m1_n1_m2_n2,
            make_tuple(make_pass_through_transform(M0),
                       make_pass_through_transform(N0),
                       make_pass_through_transform(M1),
                       make_pass_through_transform(N1),
                       make_unmerge_transform(make_tuple(Number<mmac_instr.num_groups_per_blk>{},
                                                         Number<mmac_instr.num_input_blks>{},
                                                         Number<mmac_instr.group_size>{})),
                       make_pass_through_transform(Number<mmac_instr.num_threads_per_blk>{})),
            make_tuple(Sequence<0>{},
                       Sequence<1>{},
                       Sequence<2>{},
                       Sequence<3>{},
                       Sequence<4>{},
                       Sequence<5>{}),
            make_tuple(Sequence<0>{},
                       Sequence<1>{},
                       Sequence<2>{},
                       Sequence<3>{},
                       Sequence<4, 5, 6>{},
                       Sequence<7>{}));
    }

    // mmac output C
    // M2_N2 -> M2_M3_M4_N2_N3_N4_N5_N6
    template <typename CDesc_M0_N0_M1_N1_M2_N2_M3_N3>
    __host__ __device__ static constexpr auto MakeCDescriptorInterleaved12D(
        const CDesc_M0_N0_M1_N1_M2_N2_M3_N3& c_desc_m0_n0_m1_n1_m2_n2_m3_n3)
    {
        const auto M0 = c_desc_m0_n0_m1_n1_m2_n2_m3_n3.GetLength(I0);
        const auto N0 = c_desc_m0_n0_m1_n1_m2_n2_m3_n3.GetLength(I1);
        const auto M1 = c_desc_m0_n0_m1_n1_m2_n2_m3_n3.GetLength(I2);
        const auto N1 = c_desc_m0_n0_m1_n1_m2_n2_m3_n3.GetLength(I3);

        if constexpr(!TransposeC)
        {
            return transform_tensor_descriptor(
                c_desc_m0_n0_m1_n1_m2_n2_m3_n3,
                make_tuple(
                    make_pass_through_transform(M0),
                    make_pass_through_transform(N0),
                    make_pass_through_transform(M1),
                    make_pass_through_transform(N1),
                    make_pass_through_transform(MmmacRepeat),
                    make_pass_through_transform(NmmacRepeat),
                    make_unmerge_transform(make_tuple(Number<mmac_instr.num_threads_per_blk>{},
                                                      Number<MmmacInterleave>{})),
                    make_unmerge_transform(make_tuple(Number<mmac_instr.num_groups_per_blk>{},
                                                      Number<mmac_instr.num_input_blks>{},
                                                      Number<mmac_instr.group_size>{},
                                                      Number<NmmacInterleave>{}))),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2>{},
                           Sequence<3>{},
                           Sequence<4>{},
                           Sequence<5>{},
                           Sequence<6>{},
                           Sequence<7>{}),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2>{},
                           Sequence<3>{},
                           Sequence<4>{},
                           Sequence<5>{},
                           Sequence<6, 7>{},
                           Sequence<8, 9, 10, 11>{}));
        }
        else
        {
            return transform_tensor_descriptor(
                c_desc_m0_n0_m1_n1_m2_n2_m3_n3,
                make_tuple(
                    make_pass_through_transform(M0),
                    make_pass_through_transform(N0),
                    make_pass_through_transform(M1),
                    make_pass_through_transform(N1),
                    make_pass_through_transform(MmmacRepeat),
                    make_pass_through_transform(NmmacRepeat),
                    make_unmerge_transform(make_tuple(Number<mmac_instr.num_groups_per_blk>{},
                                                      Number<mmac_instr.num_input_blks>{},
                                                      Number<mmac_instr.group_size>{},
                                                      Number<MmmacInterleave>{})),
                    make_unmerge_transform(make_tuple(Number<mmac_instr.num_threads_per_blk>{},
                                                      Number<NmmacInterleave>{}))),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2>{},
                           Sequence<3>{},
                           Sequence<4>{},
                           Sequence<5>{},
                           Sequence<6>{},
                           Sequence<7>{}),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2>{},
                           Sequence<3>{},
                           Sequence<4>{},
                           Sequence<5>{},
                           Sequence<6, 7, 8, 9>{},
                           Sequence<10, 11>{}));
        }
    }

    __device__ static constexpr index_t GetRegSizePerMmac()
    {
        return MPerMmac * NPerMmac / mmac_instr.wave_size;
    }

    __device__ static constexpr index_t GetWaveSize() { return mmac_instr.wave_size; }

    template <typename A, typename B, typename C>
    __device__ void Run(const A& p_a_thread, const B& p_b_thread, C& p_c_thread) const
    {
        // ADataType must be a scalar type
        static_assert(is_same<ADataType, double>::value || is_same<ADataType, float>::value ||
                      is_same<ADataType, tf32_t>::value || is_same<ADataType, half_t>::value ||
                      is_same<ADataType, bhalf_t>::value || is_same<ADataType, int8_t>::value ||
                      is_same<ADataType, uint8_t>::value
#ifdef CK_EXPERIMENTAL_BIT_INT_EXTENSION
                      || is_same<ADataType, fp8_t>::value || is_same<ADataType, bf8_t>::value ||
                      is_same<ADataType, int4_t>::value || is_same<ADataType, uint4_t>::value
#endif
        );

        // BDataType must be a scalar type
        static_assert(is_same<BDataType, double>::value || is_same<BDataType, float>::value ||
                      is_same<BDataType, tf32_t>::value || is_same<BDataType, half_t>::value ||
                      is_same<BDataType, bhalf_t>::value || is_same<BDataType, int8_t>::value ||
                      is_same<BDataType, uint8_t>::value
#ifdef CK_EXPERIMENTAL_BIT_INT_EXTENSION
                      || is_same<BDataType, fp8_t>::value || is_same<BDataType, bf8_t>::value ||
                      is_same<BDataType, int4_t>::value || is_same<BDataType, uint4_t>::value
#endif
        );

        static_for<0, KPack / mmac_instr.k_per_blk, 1>{}([&](auto k) {
            if constexpr(!TransposeC)
            {
                mmac_instr.run(p_a_thread[k], p_b_thread[k], p_c_thread);
            }
            else
            {
                mmac_instr.run(p_b_thread[k], p_a_thread[k], p_c_thread);
            }
        });
    }

    template <typename A, typename B, typename C>
    __device__ void RunOnce(const A& p_a_thread, const B& p_b_thread, C& p_c_thread) const
    {
        // ADataType must be a scalar type
        static_assert(is_same<ADataType, double>::value || is_same<ADataType, float>::value ||
                      is_same<ADataType, tf32_t>::value || is_same<ADataType, half_t>::value ||
                      is_same<ADataType, bhalf_t>::value || is_same<ADataType, int8_t>::value ||
                      is_same<ADataType, uint8_t>::value
#ifdef CK_EXPERIMENTAL_BIT_INT_EXTENSION
                      || is_same<ADataType, fp8_t>::value || is_same<ADataType, bf8_t>::value ||
                      is_same<ADataType, int4_t>::value || is_same<ADataType, uint4_t>::value
#endif
        );

        // BDataType must be a scalar type
        static_assert(is_same<BDataType, double>::value || is_same<BDataType, float>::value ||
                      is_same<BDataType, tf32_t>::value || is_same<BDataType, half_t>::value ||
                      is_same<BDataType, bhalf_t>::value || is_same<BDataType, int8_t>::value ||
                      is_same<BDataType, uint8_t>::value
#ifdef CK_EXPERIMENTAL_BIT_INT_EXTENSION
                      || is_same<BDataType, fp8_t>::value || is_same<BDataType, bf8_t>::value ||
                      is_same<BDataType, int4_t>::value || is_same<BDataType, uint4_t>::value
#endif
        );

        if constexpr(!TransposeC)
        {
            mmac_instr.run(p_a_thread, p_b_thread, p_c_thread);
        }
        else
        {
            mmac_instr.run(p_b_thread, p_a_thread, p_c_thread);
        }
    }

    __device__ static auto GetLaneId() { return get_thread_local_1d_id() % mmac_instr.wave_size; }

    __device__ static auto GetBlkIdx()
    {
        const auto laneId = GetLaneId();

        constexpr auto threadidx_to_blk_idx_adaptor = make_single_stage_tensor_adaptor(
            make_tuple(make_merge_transform(
                make_tuple(mmac_instr.num_input_blks, mmac_instr.num_threads_per_blk))),
            make_tuple(Sequence<0, 1>{}),
            make_tuple(Sequence<0>{}));

        const auto blk_idx =
            threadidx_to_blk_idx_adaptor.CalculateBottomIndex(make_multi_index(laneId));

        const auto blk_id = blk_idx[I0];
        const auto blk_td = blk_idx[I1];

        return make_tuple(blk_id, blk_td);
    }

    __host__ __device__ static auto CalculateAThreadOriginDataIndex()
    {
        const auto blk_idx = GetBlkIdx();

        const auto blk_id = blk_idx[I0];
        const auto blk_td = blk_idx[I1];

        // (k, m)
        return make_tuple(blk_id, blk_td);
    }

    __host__ __device__ static auto CalculateBThreadOriginDataIndex()
    {
        const auto blk_idx = GetBlkIdx();

        const auto blk_id = blk_idx[I0];
        const auto blk_td = blk_idx[I1];

        // (k, n)
        return make_tuple(blk_id, blk_td);
    }

    __device__ static CIndex GetBeginOfThreadBlk()
    {
        const auto blk_idx = GetBlkIdx();

        const auto blk_id = blk_idx[I0];
        const auto blk_td = blk_idx[I1];

        index_t m_offset = blk_td;
        index_t n_offset = blk_id * mmac_instr.group_size;

        // transposeC: contiguous on dim n, no-transposeC: contiguous on dim m
        return TransposeC ? CIndex{n_offset, m_offset} : CIndex{m_offset, n_offset};
    }

    __device__ static CIndex4D GetBeginOfThreadBlk4D()
    {
        const auto blk_idx = GetBlkIdx();

        const auto blk_id = blk_idx[I0];
        const auto blk_td = blk_idx[I1];

        // transposeC: m2_m3_m4_n2, no-transposeC: m2_n2_n3_n4
        return TransposeC ? CIndex4D{I0, blk_id, I0, blk_td} : CIndex4D{blk_td, I0, blk_id, I0};
    }

    static constexpr auto mmac =
        MmacSelector<ADataType, BDataType, MPerMmac, NPerMmac, KPerBlock, TransposeC>{};

    static constexpr auto mmac_instr = mmac.selected_mmac;

    static constexpr auto KPerMmac  = mmac.GetKPerMmac();
    static constexpr auto K1PerMmac = mmac.GetK1PerMmac();
    static constexpr auto K0PerMmac = KPerMmac / K1PerMmac;

    __host__ __device__ static constexpr auto GetCMN0N1N2ThreadBlkLengths()
    {
        return make_tuple(
            I1, Number<mmac_instr.num_groups_per_blk>{}, I1, Number<mmac_instr.group_size>{});
    }
};

} // namespace ck
