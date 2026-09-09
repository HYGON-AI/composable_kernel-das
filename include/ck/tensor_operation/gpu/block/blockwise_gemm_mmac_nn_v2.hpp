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
          typename AM0K0K1M1BlockDesc,
          typename BNKBlockDesc,
          index_t ABlockTransReadSize,
          index_t BBlockTransReadSize,
          index_t MPerMmac,
          index_t NPerMmac,
          index_t KPack,
          index_t MwaveRepeat,
          index_t NwaveRepeat,
          index_t MmmacRepeat,
          index_t NmmacRepeat,
          index_t MmmacInterleave,
          index_t NmmacInterleave,
          index_t NumGemmKPrefetchStage,
          bool HasMainLoop>
struct BlockwiseGemmASmemBSmemCReg_mmac_nn_m0k0k1m1_nk_nm_v1
{
    static constexpr auto I0 = Number<0>{};
    static constexpr auto I1 = Number<1>{};
    static constexpr auto I2 = Number<2>{};
    static constexpr auto I3 = Number<3>{};
    static constexpr auto I4 = Number<4>{};
    static constexpr auto I5 = Number<5>{};
    static constexpr auto I6 = Number<6>{};
    static constexpr auto I7 = Number<7>{};

    static constexpr bool TransposeC = false;

    using ThisThreadBlock = ThisThreadBlock<BlockSize>;

    static constexpr index_t WaveSize = get_warp_size();

    static constexpr index_t M0PerBlock = AM0K0K1M1BlockDesc{}.GetLength(I0);
    static constexpr index_t M1PerBlock = AM0K0K1M1BlockDesc{}.GetLength(I3);
    static constexpr index_t MPerBlock  = M0PerBlock * M1PerBlock;
    static constexpr index_t NPerBlock  = BNKBlockDesc{}.GetLength(I0);
    static constexpr index_t K0PerBlock = AM0K0K1M1BlockDesc{}.GetLength(I1);
    static constexpr index_t K1PerBlock = AM0K0K1M1BlockDesc{}.GetLength(I2);
    static constexpr index_t KPerBlock  = K0PerBlock * K1PerBlock;

    using AStorageType = typename storage_type<ADataType>::type;
    using BStorageType = typename storage_type<BDataType>::type;

    static constexpr auto a_dsreadm = DsReadm<ADataType, M1PerBlock, K1PerBlock, MmmacInterleave>{};

    // static constexpr auto KPack = a_dsreadm.dsreadm_instr.k_per_thread;

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

    static constexpr index_t MmmacPerDsreadm =
        a_dsreadm.dsreadm_instr.num_elems_per_thread / a_dsreadm.dsreadm_instr.k_per_thread;

    // M0 -> M0_M1_M2
    // M0: MwaveRepeat, M1: MWaves, M2: MdsreadmRepeat
    static constexpr index_t MdsreadmRepeat = M0PerBlock / (MwaveRepeat * MWaves);

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

    __device__ static auto CalculateBThreadOriginDataIndex_N0_N1_N2_N3_N4_K0_K1()
    {
        const auto wave_idx = GetWaveIdx();

        const auto wave_idx_n = wave_idx[I1];

        // (k, n)
        const auto mmac_b_idx = mmac_gemm.CalculateBThreadOriginDataIndex();

        // (n0, n1, n2, n3, n4, k0, k1)
        return make_tuple(0, wave_idx_n, 0, mmac_b_idx[I1], 0, 0, KPack * mmac_b_idx[I0]);
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

    __host__ __device__ static constexpr auto MakeABlockDescriptor_M0_M1_M2_K0_K1_M3()
    {
        return transform_tensor_descriptor(
            AM0K0K1M1BlockDesc{},
            make_tuple(make_unmerge_transform(make_tuple(
                           Number<MwaveRepeat>{}, Number<MWaves>{}, Number<MdsreadmRepeat>{})),
                       make_pass_through_transform(Number<K0PerBlock>{}),
                       make_pass_through_transform(Number<K1PerBlock>{}),
                       make_pass_through_transform(Number<M1PerBlock>{})),
            make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
            make_tuple(Sequence<0, 1, 2>{}, Sequence<3>{}, Sequence<4>{}, Sequence<5>{}));
    }

    __host__ __device__ static constexpr auto MakeBBlockDescriptor_N0_N1_N2_N3_N4_K0_K1()
    {
        return transform_tensor_descriptor(
            BNKBlockDesc{},
            make_tuple(
                make_unmerge_transform(make_tuple(Number<NwaveRepeat>{},
                                                  Number<NWaves>{},
                                                  Number<NmmacRepeat>{},
                                                  Number<NPerMmac>{},
                                                  Number<NmmacInterleave>{})),
                make_unmerge_transform(make_tuple(Number<K0PerBlock>{}, Number<K1PerBlock>{}))),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<0, 1, 2, 3, 4>{}, Sequence<5, 6>{}));
    }

    __host__ __device__ BlockwiseGemmASmemBSmemCReg_mmac_nn_m0k0k1m1_nk_nm_v1()
    {
        static_assert(AM0K0K1M1BlockDesc::IsKnownAtCompileTime() &&
                          BNKBlockDesc::IsKnownAtCompileTime(),
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

        // transposed mmac C layout
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

    template <typename ABlockBuffer, typename BBlockBuffer>
    __device__ void DsReadAB(const ABlockBuffer& a_block_buf, const BBlockBuffer& b_block_buf)
    {
        {
            const auto wave_idx   = GetWaveIdx();
            const auto wave_idx_m = wave_idx[I0];
            const auto lane_idx   = a_dsreadm.CalculateThreadOriginDataIndex();

            using SpaceFillingCurve =
                SpaceFillingCurve<Sequence<MwaveRepeat, MdsreadmRepeat, KdsreadmRepeat>,
                                  Sequence<0, 1, 2>,
                                  Sequence<1, 1, 1>>;

            constexpr auto num_access = SpaceFillingCurve::GetNumOfAccess();

            static_for<0, num_access, 1>{}([&](auto access_id) {
                constexpr auto idx              = SpaceFillingCurve::GetIndex(access_id);
                constexpr auto m_wave_repeat    = idx.At(Number<0>{});
                constexpr auto m_dsreadm_repeat = idx.At(Number<1>{});
                constexpr auto k_dsreadm_repeat = idx.At(Number<2>{});

                index_t lds_offset =
                    a_block_desc_m0_m1_k0_k1_m3.CalculateOffset(make_tuple(m_wave_repeat,
                                                                           wave_idx_m,
                                                                           m_dsreadm_repeat,
                                                                           k_dsreadm_repeat,
                                                                           lane_idx[I0],
                                                                           lane_idx[I1]));
                constexpr index_t reg_offset = a_thread_desc_.CalculateOffset(
                    make_tuple(m_wave_repeat, m_dsreadm_repeat, k_dsreadm_repeat, I0));

                using a_vec_type =
                    typename vector_type<AStorageType, a_dsreadm.GetVecSizePerRead()>::type;

                a_dsreadm.Run(a_block_buf.p_data_ + lds_offset,
                              a_thread_buf_.GetVectorTypeReference(Number<reg_offset>{})
                                  .template AsType<a_vec_type>()(Number<0>{}));
            });
        }

        {
            b_thread_copy_.Run(b_block_desc_n0_n1_n2_n3_n4_k0_k1,
                               make_tuple(I0, I0, I0, I0, I0, I0, I0),
                               b_block_buf,
                               b_thread_desc_,
                               make_tuple(I0, I0, I0, I0, I0, I0, I0),
                               b_thread_buf_);
        }
    }

    template <typename CThreadBuffer>
    __device__ void Mmac(CThreadBuffer& c_thread_buf) const
    {
        using SpaceFillingCurve = SpaceFillingCurve<Sequence<MwaveRepeat,
                                                             NwaveRepeat,
                                                             NmmacRepeat,
                                                             NmmacInterleave,
                                                             MdsreadmRepeat,
                                                             KdsreadmRepeat>,
                                                    Sequence<0, 1, 2, 3, 4, 5>,
                                                    Sequence<1, 1, 1, 1, 1, 1>>;

        constexpr auto num_access = SpaceFillingCurve::GetNumOfAccess();

        static_for<0, num_access, 1>{}([&](auto access_id) {
            constexpr auto idx = SpaceFillingCurve::GetIndex(access_id);

            constexpr auto m_wave_repeat     = idx.At(Number<0>{});
            constexpr auto n_wave_repeat     = idx.At(Number<1>{});
            constexpr auto n_mmac_repeat     = idx.At(Number<2>{});
            constexpr auto n_mmac_interleave = idx.At(Number<3>{});
            constexpr auto m_dsreadm_repeat  = idx.At(Number<4>{});
            constexpr auto k_dsreadm_repeat  = idx.At(Number<5>{});

            constexpr index_t a_reg_offset = a_thread_desc_.CalculateOffset(
                make_tuple(m_wave_repeat, m_dsreadm_repeat, k_dsreadm_repeat, I0));

            using mmac_a_input_type = typename vector_type<AStorageType, mmac_gemm.K1PerMmac>::type;

            using mmac_b_input_type = typename vector_type<BStorageType, mmac_gemm.K1PerMmac>::type;

            vector_type<AStorageType, KPack> b_thread_vec;

            static_for<0, KPack, 1>{}([&](auto i) {
                b_thread_vec.template AsType<BStorageType>()(i) = b_thread_buf_
                    [Number<b_thread_desc_.CalculateOffset(make_tuple(n_wave_repeat,
                                                                      0,
                                                                      n_mmac_repeat,
                                                                      0,
                                                                      n_mmac_interleave,
                                                                      k_dsreadm_repeat,
                                                                      i))>{}];
            });

            const auto a_thread_vec_m_k =
                a_thread_buf_.GetVectorTypeReference(Number<a_reg_offset>{});

            static_for<0, MmmacPerDsreadm, 1>{}([&](auto m_mmac_dsreadm) {
                if constexpr(MmmacInterleave == 1)
                {
                    constexpr index_t m_mmac_repeat =
                        m_dsreadm_repeat * MmmacPerDsreadm + m_mmac_dsreadm;

                    constexpr index_t c_offset =
                        c_thread_desc_.CalculateOffset(make_tuple(m_wave_repeat,
                                                                  n_wave_repeat,
                                                                  m_mmac_repeat,
                                                                  n_mmac_repeat,
                                                                  I0,
                                                                  n_mmac_interleave,
                                                                  I0));

                    mmac_gemm.RunOnce(
                        a_thread_vec_m_k.template AsType<mmac_a_input_type>()[m_mmac_dsreadm],
                        b_thread_vec.template AsType<mmac_b_input_type>()[I0],
                        c_thread_buf.GetVectorTypeReference(Number<c_offset>{}));
                }
                else
                {
                    constexpr index_t m_mmac_repeat     = m_dsreadm_repeat;
                    constexpr index_t m_mmac_interleave = m_mmac_dsreadm;

                    constexpr index_t c_offset =
                        c_thread_desc_.CalculateOffset(make_tuple(m_wave_repeat,
                                                                  n_wave_repeat,
                                                                  m_mmac_repeat,
                                                                  n_mmac_repeat,
                                                                  m_mmac_interleave,
                                                                  n_mmac_interleave,
                                                                  I0));

                    mmac_gemm.RunOnce(
                        a_thread_vec_m_k.template AsType<mmac_a_input_type>()[m_mmac_dsreadm],
                        b_thread_vec.template AsType<mmac_b_input_type>()[I0],
                        c_thread_buf.GetVectorTypeReference(Number<c_offset>{}));
                }
                if constexpr(access_id == 0 && m_mmac_dsreadm == 0)
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

    static constexpr auto a_block_desc_m0_m1_k0_k1_m3 = MakeABlockDescriptor_M0_M1_M2_K0_K1_M3();

    static constexpr auto b_block_desc_n0_n1_n2_n3_n4_k0_k1 =
        MakeBBlockDescriptor_N0_N1_N2_N3_N4_K0_K1();

    protected:
    // A[M0, M1, M2, K0, K1, M3]
    static constexpr auto a_thread_desc_ =
        make_naive_tensor_descriptor_packed(make_tuple(Number<MwaveRepeat>{},
                                                       Number<MdsreadmRepeat>{},
                                                       Number<KdsreadmRepeat>{},
                                                       a_dsreadm.GetVecSizePerRead()));

    // B[N0, N1, N2, N3, N4, KdsreadmRepeat, KPack]
    static constexpr auto b_thread_desc_ =
        make_naive_tensor_descriptor_packed(make_tuple(Number<NwaveRepeat>{},
                                                       I1,
                                                       Number<NmmacRepeat>{},
                                                       I1,
                                                       Number<NmmacInterleave>{},
                                                       Number<KdsreadmRepeat>{},
                                                       Number<KPack>{}));

    // C[M, N, NumElemsPerMmac]
    static constexpr auto c_thread_desc_ =
        make_naive_tensor_descriptor_packed(make_tuple(Number<MwaveRepeat>{},
                                                       Number<NwaveRepeat>{},
                                                       Number<MmmacRepeat>{},
                                                       Number<NmmacRepeat>{},
                                                       Number<MmmacInterleave>{},
                                                       Number<NmmacInterleave>{},
                                                       mmac_gemm.GetRegSizePerMmac()));

    using BThreadCopy = ThreadwiseTensorSliceTransfer_SwizzledLds2Vgpr<
        AStorageType,
        AStorageType,
        decltype(b_block_desc_n0_n1_n2_n3_n4_k0_k1),
        decltype(b_thread_desc_),
        Sequence<NwaveRepeat, 1, NmmacRepeat, 1, NmmacInterleave, KdsreadmRepeat, KPack>,
        Sequence<0, 1, 2, 3, 4, 5, 6>,
        6,
        KPack>;

    BThreadCopy b_thread_copy_{CalculateBThreadOriginDataIndex_N0_N1_N2_N3_N4_K0_K1()};

    StaticBufferTupleOfVector<AddressSpaceEnum::Vgpr,
                              AStorageType,
                              MwaveRepeat * MdsreadmRepeat * KdsreadmRepeat,
                              a_dsreadm.GetVecSizePerRead(),
                              true>
        a_thread_buf_;

    StaticBuffer<AddressSpaceEnum::Vgpr, BStorageType, b_thread_desc_.GetElementSpaceSize(), true>
        b_thread_buf_;

    StaticBufferTupleOfVector<AddressSpaceEnum::Vgpr,
                              AccDataType,
                              MwaveRepeat * NwaveRepeat * mmac_gemm.GetNumMmac(),
                              mmac_gemm.GetRegSizePerMmac(),
                              true>
        c_thread_buf_;
};

} // namespace ck
