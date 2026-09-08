// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck/utility/common_header.hpp"
#include "ck/tensor_operation/gpu/thread/threadwise_tensor_slice_transfer.hpp"
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
struct BlockwiseGemmASmemBSmemCReg_mmac_nt_m0k0k1m1_n0k0k1n1_mn_v1
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

    static constexpr index_t M0PerBlock = AM0K0K1M1BlockDesc{}.GetLength(I0);
    static constexpr index_t M1PerBlock = AM0K0K1M1BlockDesc{}.GetLength(I3);
    static constexpr index_t MPerBlock  = M0PerBlock * M1PerBlock;

    static constexpr index_t N0PerBlock = BN0K0K1N1BlockDesc{}.GetLength(I0);
    static constexpr index_t N1PerBlock = BN0K0K1N1BlockDesc{}.GetLength(I3);
    static constexpr index_t NPerBlock  = N0PerBlock * N1PerBlock;

    static constexpr index_t K0PerBlock = BN0K0K1N1BlockDesc{}.GetLength(I1);
    static constexpr index_t K1PerBlock = BN0K0K1N1BlockDesc{}.GetLength(I2);
    static constexpr index_t KPerBlock  = K0PerBlock * K1PerBlock;

    using AStorageType = typename storage_type<ADataType>::type;
    using BStorageType = typename storage_type<BDataType>::type;

    static constexpr auto a_dsreadm = DsReadm<ADataType, M1PerBlock, K1PerBlock, MmmacInterleave>{};

    static constexpr auto b_dsreadm = DsReadm<BDataType, N1PerBlock, K1PerBlock, NmmacInterleave>{};

    static constexpr auto mmac_gemm = MmacGemm<ADataType,
                                               BDataType,
                                               MPerMmac,
                                               NPerMmac,
                                               KPerBlock,
                                               a_dsreadm.dsreadm_instr.k_per_thread,
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

    static constexpr index_t NmmacPerDsreadm =
        b_dsreadm.dsreadm_instr.num_elems_per_thread / b_dsreadm.dsreadm_instr.k_per_thread;

    // M0 -> M0_M1_M2
    // M0: MwaveRepeat, M1: MWaves, M2: MdsreadmRepeat
    static constexpr index_t MdsreadmRepeat = M0PerBlock / (MwaveRepeat * MWaves);

    // N0 -> N0_N1_N2
    // N0: NwaveRepeat, N1: NWaves, N2: NdsreadmRepeat
    static constexpr index_t NdsreadmRepeat = N0PerBlock / (NwaveRepeat * NWaves);

    static constexpr index_t KdsreadmRepeat = K0PerBlock;

    // lds direct load cnt
    static constexpr index_t DirectLoadIssueA =
        (MPerBlock * KPerBlock / BlockSize) * sizeof(ADataType) / ABlockTransReadSize;
    static constexpr index_t DirectLoadIssueB =
        (NPerBlock * KPerBlock / BlockSize) * sizeof(BDataType) / BBlockTransReadSize;

    static constexpr index_t DirectLoadIssuePerStage = DirectLoadIssueA + DirectLoadIssueB;

    StaticBufferTupleOfVector<AddressSpaceEnum::Vgpr,
                              AStorageType,
                              MwaveRepeat * MdsreadmRepeat * KdsreadmRepeat,
                              a_dsreadm.GetVecSizePerRead(),
                              true>
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

    __host__ __device__ BlockwiseGemmASmemBSmemCReg_mmac_nt_m0k0k1m1_n0k0k1n1_mn_v1()
    {
        static_assert(AM0K0K1M1BlockDesc::IsKnownAtCompileTime() &&
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

    static constexpr auto a_block_desc_m0_m1_m2_k0_k1_m3 = MakeABlockDescriptor_M0_M1_M2_K0_K1_M3();
    static constexpr auto b_block_desc_n0_n1_n2_k0_k1_n3 = MakeBBlockDescriptor_N0_N1_N2_K0_K1_N3();

    template <typename ABlockBuffer, typename BBlockBuffer>
    __device__ void DsReadAB(const ABlockBuffer& a_block_buf, const BBlockBuffer& b_block_buf)
    {
        const auto wave_idx = GetWaveIdx();

        const auto wave_idx_m = wave_idx[I0];
        const auto wave_idx_n = wave_idx[I1];

        {
            const auto lane_idx = a_dsreadm.CalculateThreadOriginDataIndex();

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
                    a_block_desc_m0_m1_m2_k0_k1_m3.CalculateOffset(make_tuple(m_wave_repeat,
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

        // dsread B
        {
            const auto lane_idx = b_dsreadm.CalculateThreadOriginDataIndex();

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
                    b_block_desc_n0_n1_n2_k0_k1_n3.CalculateOffset(make_tuple(n_wave_repeat,
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
        using SpaceFillingCurve = SpaceFillingCurve<
            Sequence<MwaveRepeat, NwaveRepeat, MdsreadmRepeat, NdsreadmRepeat, KdsreadmRepeat>,
            Sequence<0, 1, 2, 3, 4>,
            Sequence<1, 1, 1, 1, 1>>;

        constexpr auto num_access = SpaceFillingCurve::GetNumOfAccess();

        static_for<0, num_access, 1>{}([&](auto access_id) {
            constexpr auto idx = SpaceFillingCurve::GetIndex(access_id);

            constexpr auto m_wave_repeat    = idx.At(Number<0>{});
            constexpr auto n_wave_repeat    = idx.At(Number<1>{});
            constexpr auto m_dsreadm_repeat = idx.At(Number<2>{});
            constexpr auto n_dsreadm_repeat = idx.At(Number<3>{});
            constexpr auto k_dsreadm_repeat = idx.At(Number<4>{});

            constexpr index_t a_reg_offset = a_thread_desc_.CalculateOffset(
                make_tuple(m_wave_repeat, m_dsreadm_repeat, k_dsreadm_repeat, I0));

            constexpr index_t b_reg_offset = b_thread_desc_.CalculateOffset(
                make_tuple(n_wave_repeat, n_dsreadm_repeat, k_dsreadm_repeat, I0));

            using mmac_a_input_type = typename vector_type<AStorageType, mmac_gemm.K1PerMmac>::type;

            using mmac_b_input_type = typename vector_type<BStorageType, mmac_gemm.K1PerMmac>::type;

            const auto a_thread_vec_m_k =
                a_thread_buf_.GetVectorTypeReference(Number<a_reg_offset>{});
            const auto b_thread_vec_n_k =
                b_thread_buf_.GetVectorTypeReference(Number<b_reg_offset>{});

            static_for<0, MmmacPerDsreadm, 1>{}([&](auto m_mmac_dsreadm) {
                static_for<0, NmmacPerDsreadm, 1>{}([&](auto n_mmac_dsreadm) {
                    if constexpr(MmmacInterleave == 1 && NmmacInterleave == 1)
                    {
                        constexpr index_t m_mmac_repeat =
                            m_dsreadm_repeat * MmmacPerDsreadm + m_mmac_dsreadm;
                        constexpr index_t n_mmac_repeat =
                            n_dsreadm_repeat * NmmacPerDsreadm + n_mmac_dsreadm;

                        constexpr index_t c_offset =
                            c_thread_desc_.CalculateOffset(make_tuple(m_wave_repeat,
                                                                      n_wave_repeat,
                                                                      m_mmac_repeat,
                                                                      n_mmac_repeat,
                                                                      I0,
                                                                      I0,
                                                                      I0));

                        mmac_gemm.RunOnce(
                            a_thread_vec_m_k.template AsType<mmac_a_input_type>()[m_mmac_dsreadm],
                            b_thread_vec_n_k.template AsType<mmac_b_input_type>()[n_mmac_dsreadm],
                            c_thread_buf.GetVectorTypeReference(Number<c_offset>{}));
                    }
                    else if constexpr(MmmacInterleave == 1 && NmmacInterleave != 1)
                    {
                        constexpr index_t m_mmac_repeat =
                            m_dsreadm_repeat * MmmacPerDsreadm + m_mmac_dsreadm;
                        constexpr index_t n_mmac_repeat     = n_dsreadm_repeat;
                        constexpr index_t n_mmac_interleave = n_mmac_dsreadm;

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
                            b_thread_vec_n_k.template AsType<mmac_b_input_type>()[n_mmac_dsreadm],
                            c_thread_buf.GetVectorTypeReference(Number<c_offset>{}));
                    }
                    else if constexpr(MmmacInterleave != 1 && NmmacInterleave == 1)
                    {
                        constexpr index_t m_mmac_repeat     = m_dsreadm_repeat;
                        constexpr index_t m_mmac_interleave = m_mmac_dsreadm;
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
                            a_thread_vec_m_k.template AsType<mmac_a_input_type>()[m_mmac_dsreadm],
                            b_thread_vec_n_k.template AsType<mmac_b_input_type>()[n_mmac_dsreadm],
                            c_thread_buf.GetVectorTypeReference(Number<c_offset>{}));
                    }
                    else
                    {
                        constexpr index_t m_mmac_repeat     = m_dsreadm_repeat;
                        constexpr index_t m_mmac_interleave = m_mmac_dsreadm;
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
                            a_thread_vec_m_k.template AsType<mmac_a_input_type>()[m_mmac_dsreadm],
                            b_thread_vec_n_k.template AsType<mmac_b_input_type>()[n_mmac_dsreadm],
                            c_thread_buf.GetVectorTypeReference(Number<c_offset>{}));
                    }

                    if constexpr(access_id == 0 && m_mmac_dsreadm == 0 && n_mmac_dsreadm == 0)
                    {
                        __builtin_amdgcn_sched_barrier(0);
                        __builtin_amdgcn_s_setprio(1);
                        __builtin_amdgcn_sched_barrier(0);
                    }
                });
            });
        });
        __builtin_amdgcn_sched_barrier(0);
        __builtin_amdgcn_s_setprio(0);
        __builtin_amdgcn_sched_barrier(0);
    }

    protected:
    // A[M0, M1, M2, K0, K1, M3]
    static constexpr auto a_thread_desc_ =
        make_naive_tensor_descriptor_packed(make_tuple(Number<MwaveRepeat>{},
                                                       Number<MdsreadmRepeat>{},
                                                       Number<KdsreadmRepeat>{},
                                                       a_dsreadm.GetVecSizePerRead()));

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
};

} // namespace ck
