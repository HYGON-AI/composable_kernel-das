// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include "ck/utility/common_header.hpp"
#include "ck/tensor_operation/gpu/thread/threadwise_tensor_slice_transfer_swizzled_lds_to_vgpr.hpp"
#include "ck/tensor_operation/gpu/warp/dsread_matrix.hpp"
#include "ck/tensor_operation/gpu/warp/mmac_gemm.hpp"
#include "ck/tensor_description/tensor_adaptor.hpp"
#include "ck/tensor_description/tensor_space_filling_curve.hpp"

namespace ck {

template <index_t BlockSize,
          typename ADataType,
          typename BDataType,
          typename AccDataType,
          typename AMKBlockDesc,
          typename BN0K0K1N1BlockDesc,
          index_t ABlockTransReadSize,
          index_t BBlockTransReadSize,
          index_t MPerMmac,
          index_t NPerMmac,
          index_t MwaveRepeat,
          index_t NwaveRepeat,
          index_t MmmacRepeat,
          index_t NmmacRepeat,
          index_t MmmacInterleave,
          index_t NmmacInterleave,
          index_t NumGemmKPrefetchStage,
          bool HasMainLoop,
          bool TransposeC = true>
struct BlockwiseGemmASmemBSmemCReg_mmac_tt_mk_n0k0k1n1_mn_v2
{
    static constexpr auto I0 = Number<0>{};
    static constexpr auto I1 = Number<1>{};
    static constexpr auto I2 = Number<2>{};
    static constexpr auto I3 = Number<3>{};
    static constexpr auto I4 = Number<4>{};
    static constexpr auto I5 = Number<5>{};
    static constexpr auto I6 = Number<6>{};
    static constexpr auto I7 = Number<7>{};

    using ThisThreadBlock = ThisThreadBlock<BlockSize>;

    static constexpr index_t WaveSize = get_warp_size();

    static constexpr index_t MPerBlock = AMKBlockDesc{}.GetLength(I0);

    static constexpr index_t N0PerBlock = BN0K0K1N1BlockDesc{}.GetLength(I0);
    static constexpr index_t N1PerBlock = BN0K0K1N1BlockDesc{}.GetLength(I3);
    static constexpr index_t NPerBlock  = N0PerBlock * N1PerBlock;

    static constexpr index_t KPerBlock  = AMKBlockDesc{}.GetLength(I1);
    static constexpr index_t K0PerBlock = BN0K0K1N1BlockDesc{}.GetLength(I1);
    static constexpr index_t K1PerBlock = BN0K0K1N1BlockDesc{}.GetLength(I2);

    using AStorageType = typename storage_type<ADataType>::type;
    using BStorageType = typename storage_type<BDataType>::type;

    static constexpr auto b_dsreadm = DsReadm<BDataType, N1PerBlock, K1PerBlock, NmmacInterleave>{};

    static constexpr auto KPack = b_dsreadm.dsreadm_instr.k_per_thread;

    static constexpr auto mmac_gemm = MmacGemm<ADataType,
                                               BDataType,
                                               MPerMmac,
                                               NPerMmac,
                                               KPerBlock,
                                               KPack,
                                               TransposeC,
                                               MmmacRepeat,
                                               NmmacRepeat,
                                               MmmacInterleave,
                                               NmmacInterleave>{};

    static constexpr index_t KPerThread = KPerBlock / mmac_gemm.K0PerMmac;

    static constexpr index_t MWaves =
        MPerBlock / (MwaveRepeat * MmmacRepeat * MPerMmac * MmmacInterleave);
    static constexpr index_t NWaves =
        NPerBlock / (NwaveRepeat * NmmacRepeat * NPerMmac * NmmacInterleave);

    static constexpr index_t NmmacPerDsreadm =
        b_dsreadm.dsreadm_instr.num_elems_per_thread / b_dsreadm.dsreadm_instr.k_per_thread;

    // N0 -> N0_N1_N2
    // N0: NwaveRepeat, N1: NWaves, N2: NdsreadmRepeat
    static constexpr index_t NdsreadmRepeat = N0PerBlock / (NwaveRepeat * NWaves);

    static constexpr index_t KdsreadmRepeat = K0PerBlock;

    // limitation
    static_assert(K1PerBlock == mmac_gemm.KPerMmac);

    // lds direct load cnt
    static constexpr index_t DirectLoadIssueA =
        (MPerBlock * KPerBlock / BlockSize) * sizeof(ADataType) / ABlockTransReadSize;
    static constexpr index_t DirectLoadIssueB =
        (NPerBlock * KPerBlock / BlockSize) * sizeof(BDataType) / BBlockTransReadSize;

    static constexpr index_t DirectLoadIssuePerStage = DirectLoadIssueA + DirectLoadIssueB;

    __host__ __device__ constexpr auto& GetCThreadBuffer() { return c_thread_buf_; }

    __device__ static auto GetWaveIdx()
    {
        const index_t thread_id = ThisThreadBlock::GetThreadId();

        // wave schedule order: n -> m
        constexpr auto threadid_to_wave_idx_adaptor = make_single_stage_tensor_adaptor(
            make_tuple(make_merge_transform(make_tuple(MWaves, NWaves, WaveSize))),
            make_tuple(Sequence<0, 1, 2>{}),
            make_tuple(Sequence<0>{}));

        return threadid_to_wave_idx_adaptor.CalculateBottomIndex(make_multi_index(thread_id));
    }

    __device__ static auto CalculateAThreadOriginDataIndex_M0_M1_M2_M3_M4_K0_K1()
    {
        const auto wave_idx = GetWaveIdx();

        const auto wave_idx_m = wave_idx[I0];

        // (k, m)
        const auto mmac_a_idx = mmac_gemm.CalculateAThreadOriginDataIndex();

        // (m0, m1, m2, m3, m4, k0, k1)
        return make_tuple(0, wave_idx_m, 0, mmac_a_idx[I1], 0, 0, KPack * mmac_a_idx[I0]);
    }

    template <index_t m_waverepeat,
              index_t n_waverepeat,
              index_t m_mmacrepeat,
              index_t n_mmacrepeat>
    __device__ static auto CalculateCThreadOriginDataIndex(Number<m_waverepeat>,
                                                           Number<n_waverepeat>,
                                                           Number<m_mmacrepeat>,
                                                           Number<n_mmacrepeat>)
    {
        const auto wave_idx = GetWaveIdx();

        const auto wave_idx_m = wave_idx[I0];
        const auto wave_idx_n = wave_idx[I1];

        const auto blk_idx = mmac_gemm.GetBeginOfThreadBlk();

        constexpr auto mrepeat_mwave_mmmacrepeat_mpermmacminterleave_to_m_adaptor =
            make_single_stage_tensor_adaptor(
                make_tuple(make_unmerge_transform(
                    make_tuple(MwaveRepeat, MWaves, MmmacRepeat, MPerMmac, MmmacInterleave))),
                make_tuple(Sequence<0>{}),
                make_tuple(Sequence<0, 1, 2, 3, 4>{}));

        constexpr auto nrepeat_nwave_nmmacrepeat_npermmacninterleave_to_n_adaptor =
            make_single_stage_tensor_adaptor(
                make_tuple(make_unmerge_transform(
                    make_tuple(NwaveRepeat, NWaves, NmmacRepeat, NPerMmac, NmmacInterleave))),
                make_tuple(Sequence<0>{}),
                make_tuple(Sequence<0, 1, 2, 3, 4>{}));

        const index_t c_thread_m =
            mrepeat_mwave_mmmacrepeat_mpermmacminterleave_to_m_adaptor.CalculateBottomIndex(
                make_tuple(m_waverepeat, wave_idx_m, m_mmacrepeat, blk_idx[I0], 0))[I0];
        const index_t c_thread_n =
            nrepeat_nwave_nmmacrepeat_npermmacninterleave_to_n_adaptor.CalculateBottomIndex(
                make_tuple(n_waverepeat, wave_idx_n, n_mmacrepeat, blk_idx[I1], 0))[I0];

        return make_tuple(c_thread_m, c_thread_n);
    }

    __host__ __device__ static constexpr auto MakeABlockDescriptor_M0_M1_M2_M3_M4_K0_K1()
    {
        return transform_tensor_descriptor(
            AMKBlockDesc{},
            make_tuple(
                make_unmerge_transform(make_tuple(Number<MwaveRepeat>{},
                                                  Number<MWaves>{},
                                                  Number<MmmacRepeat>{},
                                                  Number<MPerMmac>{},
                                                  Number<MmmacInterleave>{})),
                make_unmerge_transform(make_tuple(Number<K0PerBlock>{}, Number<K1PerBlock>{}))),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<0, 1, 2, 3, 4>{}, Sequence<5, 6>{}));
    }

    __host__ __device__ static constexpr auto MakeBBlockDescriptor_N0_N1_N2_K0_K1_N3()
    {
        return transform_tensor_descriptor(
            BN0K0K1N1BlockDesc{},
            make_tuple(make_unmerge_transform(make_tuple(
                           Number<NwaveRepeat>{}, Number<NWaves>{}, Number<NdsreadmRepeat>{})),
                       make_pass_through_transform(Number<K0PerBlock>{}),
                       make_pass_through_transform(Number<K1PerBlock>{}),
                       make_pass_through_transform(Number<N1PerBlock>{})),
            make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
            make_tuple(Sequence<0, 1, 2>{}, Sequence<3>{}, Sequence<4>{}, Sequence<5>{}));
    }

    __host__ __device__ BlockwiseGemmASmemBSmemCReg_mmac_tt_mk_n0k0k1n1_mn_v2()
    {
        static_assert(AMKBlockDesc::IsKnownAtCompileTime() &&
                          BN0K0K1N1BlockDesc::IsKnownAtCompileTime(),
                      "wrong! Desc should be known at compile-time");

        static_assert(ThisThreadBlock::GetNumOfThread() == MWaves * NWaves * WaveSize,
                      "ThisThreadBlock::GetNumOfThread() != MWaves * NWaves * WaveSize\n");

        static_assert(MPerBlock % (MwaveRepeat * MmmacRepeat * MPerMmac * MmmacInterleave) == 0 &&
                          NPerBlock % (NwaveRepeat * NmmacRepeat * NPerMmac * NmmacInterleave) == 0,
                      "wrong!");
    }

    __host__ __device__ static constexpr auto GetCThreadDescriptorRaw12D()
    {
        constexpr auto c_m_n0_n1_n2_lens = mmac_gemm.GetCMN0N1N2ThreadBlkLengths();

        constexpr auto num_groups_per_blk = c_m_n0_n1_n2_lens[I1];
        constexpr auto group_size         = c_m_n0_n1_n2_lens[I3];

        if constexpr(TransposeC)
        {
            // transposed mmac C layout
            return make_naive_tensor_descriptor_packed(make_tuple(Number<MwaveRepeat>{},
                                                                  Number<NwaveRepeat>{},
                                                                  I1,
                                                                  I1,
                                                                  Number<MmmacRepeat>{},
                                                                  Number<NmmacRepeat>{},
                                                                  Number<MmmacInterleave>{},
                                                                  Number<NmmacInterleave>{},
                                                                  num_groups_per_blk,
                                                                  I1,
                                                                  group_size,
                                                                  I1));
        }
        else
        {
            // non-transposed mmac C layout
            return make_naive_tensor_descriptor_packed(make_tuple(Number<MwaveRepeat>{},
                                                                  Number<NwaveRepeat>{},
                                                                  I1,
                                                                  I1,
                                                                  Number<MmmacRepeat>{},
                                                                  Number<NmmacRepeat>{},
                                                                  Number<MmmacInterleave>{},
                                                                  Number<NmmacInterleave>{},
                                                                  I1,
                                                                  num_groups_per_blk,
                                                                  I1,
                                                                  group_size));
        }
    }

    __host__ __device__ static constexpr auto GetCBlockDescriptorInterleaved12D()
    {
        constexpr auto c_block_desc_m0_n0_m1_n1_m2_n2_m3_n3 =
            make_naive_tensor_descriptor_packed(make_tuple(Number<MwaveRepeat>{},
                                                           Number<NwaveRepeat>{},
                                                           Number<MWaves>{},
                                                           Number<NWaves>{},
                                                           Number<MmmacRepeat>{},
                                                           Number<NmmacRepeat>{},
                                                           Number<MPerMmac * MmmacInterleave>{},
                                                           Number<NPerMmac * NmmacInterleave>{}));

        // tranposed blockwise Mmac C output layout
        return mmac_gemm.MakeCDescriptorInterleaved12D(c_block_desc_m0_n0_m1_n1_m2_n2_m3_n3);
    }

    template <typename CGridDesc_M_N>
    __host__ __device__ static constexpr auto
    MakeCGridDescriptorInterleaved12D(const CGridDesc_M_N& c_grid_desc_m_n)
    {
        const auto M = c_grid_desc_m_n.GetLength(I0);
        const auto N = c_grid_desc_m_n.GetLength(I1);

        // MBlocks * MwaveRepeat -> M0
        // NBlocks * NwaveRepeat -> N0
        const auto c_grid_desc_m0_n0_m1_n1_m2_n2_m3_n3 = transform_tensor_descriptor(
            c_grid_desc_m_n,
            make_tuple(make_unmerge_transform(
                           make_tuple(M / (MWaves * MmmacRepeat * MPerMmac * MmmacInterleave),
                                      MWaves,
                                      MmmacRepeat,
                                      MPerMmac * MmmacInterleave)),
                       make_unmerge_transform(
                           make_tuple(N / (NWaves * NmmacRepeat * NPerMmac * NmmacInterleave),
                                      NWaves,
                                      NmmacRepeat,
                                      NPerMmac * NmmacInterleave))),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<0, 2, 4, 6>{}, Sequence<1, 3, 5, 7>{}));

        // transposed gridwise Mmac C output layout
        return mmac_gemm.MakeCDescriptorInterleaved12D(c_grid_desc_m0_n0_m1_n1_m2_n2_m3_n3);
    }

    template <typename ABlockBuffer, typename BBlockBuffer>
    __device__ void DsReadAB(const ABlockBuffer& a_block_buf, const BBlockBuffer& b_block_buf)
    {
        {
            a_thread_copy_.Run(a_block_desc_m0_m1_m2_m3_m4_k0_k1,
                               make_tuple(I0, I0, I0, I0, I0, I0, I0),
                               a_block_buf,
                               a_thread_desc_,
                               make_tuple(I0, I0, I0, I0, I0, I0, I0),
                               a_thread_buf_);
        }

        {
            const auto wave_idx   = GetWaveIdx();
            const auto wave_idx_n = wave_idx[I1];
            const auto lane_idx   = b_dsreadm.CalculateThreadOriginDataIndex();

            using SpaceFillingCurve =
                SpaceFillingCurve<Sequence<NwaveRepeat, NdsreadmRepeat, KdsreadmRepeat>,
                                  Sequence<0, 1, 2>,
                                  Sequence<1, 1, 1>>;

            constexpr auto num_access = SpaceFillingCurve::GetNumOfAccess();

            static_for<0, num_access, 1>{}([&](auto access_id) {
                constexpr auto idx              = SpaceFillingCurve::GetIndex(access_id);
                constexpr auto n_wave_repeat    = idx.At(Number<0>{});
                constexpr auto n_dsreadm_repeat = idx.At(Number<1>{});
                constexpr auto k_dsreadm_repeat = idx.At(Number<2>{});

                index_t lds_offset =
                    b_block_desc_n0_n1_k0_k1_n3.CalculateOffset(make_tuple(n_wave_repeat,
                                                                           wave_idx_n,
                                                                           n_dsreadm_repeat,
                                                                           k_dsreadm_repeat,
                                                                           lane_idx[I0],
                                                                           lane_idx[I1]));
                constexpr index_t reg_offset = b_thread_desc_.CalculateOffset(
                    make_tuple(n_wave_repeat, n_dsreadm_repeat, k_dsreadm_repeat, I0));

                using b_vec_type =
                    typename vector_type<BStorageType, b_dsreadm.GetVecSizePerRead()>::type;

                b_dsreadm.Run(b_block_buf.p_data_ + lds_offset,
                              b_thread_buf_.GetVectorTypeReference(Number<reg_offset>{})
                                  .template AsType<b_vec_type>()(Number<0>{}));
            });
        }
    }

    template <typename CThreadBuffer>
    __device__ void Mmac(CThreadBuffer& c_thread_buf) const
    {
        using SpaceFillingCurve = SpaceFillingCurve<Sequence<MwaveRepeat,
                                                             NwaveRepeat,
                                                             MmmacRepeat,
                                                             MmmacInterleave,
                                                             NdsreadmRepeat,
                                                             KdsreadmRepeat>,
                                                    Sequence<0, 1, 2, 3, 4, 5>,
                                                    Sequence<1, 1, 1, 1, 1, 1>>;

        constexpr auto num_access = SpaceFillingCurve::GetNumOfAccess();

        static_for<0, num_access, 1>{}([&](auto access_id) {
            constexpr auto idx = SpaceFillingCurve::GetIndex(access_id);

            constexpr auto m_wave_repeat     = idx.At(Number<0>{});
            constexpr auto n_wave_repeat     = idx.At(Number<1>{});
            constexpr auto m_mmac_repeat     = idx.At(Number<2>{});
            constexpr auto m_mmac_interleave = idx.At(Number<3>{});
            constexpr auto n_dsreadm_repeat  = idx.At(Number<4>{});
            constexpr auto k_dsreadm_repeat  = idx.At(Number<5>{});

            constexpr index_t b_reg_offset = b_thread_desc_.CalculateOffset(
                make_tuple(n_wave_repeat, n_dsreadm_repeat, k_dsreadm_repeat, I0));

            using mmac_a_input_type = typename vector_type<AStorageType, mmac_gemm.K1PerMmac>::type;

            using mmac_b_input_type = typename vector_type<BStorageType, mmac_gemm.K1PerMmac>::type;

            vector_type<AStorageType, KPack> a_thread_vec;

            static_for<0, KPack, 1>{}([&](auto i) {
                a_thread_vec.template AsType<AStorageType>()(i) = a_thread_buf_
                    [Number<a_thread_desc_.CalculateOffset(make_tuple(m_wave_repeat,
                                                                      0,
                                                                      m_mmac_repeat,
                                                                      0,
                                                                      m_mmac_interleave,
                                                                      k_dsreadm_repeat,
                                                                      i))>{}];
            });

            const auto b_thread_vec_n_k =
                b_thread_buf_.GetVectorTypeReference(Number<b_reg_offset>{});

            static_for<0, NmmacPerDsreadm, 1>{}([&](auto n_mmac_dsreadm) {
                if constexpr(NmmacInterleave == 1)
                {
                    constexpr index_t n_mmac_repeat =
                        n_dsreadm_repeat * NmmacPerDsreadm + n_mmac_dsreadm;

                    constexpr index_t c_offset =
                        c_thread_desc_.CalculateOffset(make_tuple(m_wave_repeat,
                                                                  n_wave_repeat,
                                                                  m_mmac_repeat,
                                                                  n_mmac_repeat,
                                                                  m_mmac_interleave,
                                                                  I0,
                                                                  I0));

                    mmac_gemm.RunOnce(
                        a_thread_vec.template AsType<mmac_a_input_type>()[I0],
                        b_thread_vec_n_k.template AsType<mmac_b_input_type>()[n_mmac_dsreadm],
                        c_thread_buf.GetVectorTypeReference(Number<c_offset>{}));
                }
                else
                {
                    constexpr index_t n_mmac_repeat     = n_dsreadm_repeat;
                    constexpr index_t n_mmac_interleave = n_mmac_dsreadm;

                    constexpr index_t c_offset =
                        c_thread_desc_.CalculateOffset(make_tuple(m_wave_repeat,
                                                                  n_wave_repeat,
                                                                  m_mmac_repeat,
                                                                  n_mmac_repeat,
                                                                  m_mmac_interleave,
                                                                  n_mmac_interleave,
                                                                  I0));

                    mmac_gemm.RunOnce(
                        a_thread_vec.template AsType<mmac_a_input_type>()[I0],
                        b_thread_vec_n_k.template AsType<mmac_b_input_type>()[n_mmac_dsreadm],
                        c_thread_buf.GetVectorTypeReference(Number<c_offset>{}));
                }
                if constexpr(access_id == 0 && n_mmac_dsreadm == 0)
                {
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(1);
                    __builtin_amdgcn_sched_barrier(0);
                }
            });
        });
        __builtin_amdgcn_sched_barrier(0);
        __builtin_amdgcn_s_setprio(0);
        __builtin_amdgcn_sched_barrier(0);
    }

    static constexpr auto a_block_desc_m0_m1_m2_m3_m4_k0_k1 =
        MakeABlockDescriptor_M0_M1_M2_M3_M4_K0_K1();

    static constexpr auto b_block_desc_n0_n1_k0_k1_n3 = MakeBBlockDescriptor_N0_N1_N2_K0_K1_N3();

    protected:
    // A[M0, M1, M2, M3, M4, KdsreadmRepeat, KPack]
    static constexpr auto a_thread_desc_ =
        make_naive_tensor_descriptor_packed(make_tuple(Number<MwaveRepeat>{},
                                                       I1,
                                                       Number<MmmacRepeat>{},
                                                       I1,
                                                       Number<MmmacInterleave>{},
                                                       Number<KdsreadmRepeat>{},
                                                       Number<KPack>{}));

    // B[N0, N1, N2, K0, K1, N3]
    static constexpr auto b_thread_desc_ =
        make_naive_tensor_descriptor_packed(make_tuple(Number<NwaveRepeat>{},
                                                       Number<NdsreadmRepeat>{},
                                                       Number<KdsreadmRepeat>{},
                                                       b_dsreadm.GetVecSizePerRead()));

    // C[M, N, NumElemsPerMmac]
    static constexpr auto c_thread_desc_ =
        make_naive_tensor_descriptor_packed(make_tuple(Number<MwaveRepeat>{},
                                                       Number<NwaveRepeat>{},
                                                       Number<MmmacRepeat>{},
                                                       Number<NmmacRepeat>{},
                                                       Number<MmmacInterleave>{},
                                                       Number<NmmacInterleave>{},
                                                       mmac_gemm.GetRegSizePerMmac()));

    using AThreadCopy = ThreadwiseTensorSliceTransfer_SwizzledLds2Vgpr<
        AStorageType,
        AStorageType,
        decltype(a_block_desc_m0_m1_m2_m3_m4_k0_k1),
        decltype(a_thread_desc_),
        Sequence<MwaveRepeat, 1, MmmacRepeat, 1, MmmacInterleave, KdsreadmRepeat, KPack>,
        Sequence<0, 1, 2, 3, 4, 5, 6>,
        6,
        KPack>;

    AThreadCopy a_thread_copy_{CalculateAThreadOriginDataIndex_M0_M1_M2_M3_M4_K0_K1()};

    StaticBuffer<AddressSpaceEnum::Vgpr, AStorageType, a_thread_desc_.GetElementSpaceSize(), true>
        a_thread_buf_;

    StaticBufferTupleOfVector<AddressSpaceEnum::Vgpr,
                              BStorageType,
                              NwaveRepeat * NdsreadmRepeat * KdsreadmRepeat,
                              b_dsreadm.GetVecSizePerRead(),
                              true>
        b_thread_buf_;

    StaticBufferTupleOfVector<AddressSpaceEnum::Vgpr,
                              AccDataType,
                              MwaveRepeat * NwaveRepeat * mmac_gemm.GetNumMmac(),
                              mmac_gemm.GetRegSizePerMmac(),
                              true>
        c_thread_buf_;
};

} // namespace ck
