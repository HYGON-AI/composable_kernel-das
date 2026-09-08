// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.

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
          bool HasMainLoop,
          bool TransposeC = true>
struct BlockwiseGemmASmemBSmemCReg_mmac_tn_mk_nk_mn_v2
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
    static constexpr index_t NPerBlock = BNKBlockDesc{}.GetLength(I0);
    static constexpr index_t KPerBlock = BNKBlockDesc{}.GetLength(I1);

    using AStorageType = typename storage_type<ADataType>::type;
    using BStorageType = typename storage_type<BDataType>::type;

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

    __device__ static auto CalculateAThreadOriginDataIndex_M0_M1_M2_M3_M4_K()
    {
        const auto wave_idx = GetWaveIdx();

        const auto wave_idx_m = wave_idx[I0];

        // (k, m)
        const auto mmac_a_idx = mmac_gemm.CalculateAThreadOriginDataIndex();

        // (m0, m1, m2, m3, m4, k)
        return make_tuple(0, wave_idx_m, 0, mmac_a_idx[I1], 0, KPerThread * mmac_a_idx[I0]);
    }

    __device__ static auto CalculateBThreadOriginDataIndex_N0_N1_N2_N3_N4_K()
    {
        const auto wave_idx = GetWaveIdx();

        const auto wave_idx_n = wave_idx[I1];

        // (k, n)
        const auto mmac_a_idx = mmac_gemm.CalculateAThreadOriginDataIndex();

        // (n0, n1, n2, n3, n4, k)
        return make_tuple(0, wave_idx_n, 0, mmac_a_idx[I1], 0, KPerThread * mmac_a_idx[I0]);
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

    __host__ __device__ static constexpr auto MakeABlockDescriptor_M0_M1_M2_M3_M4_K()
    {
        return transform_tensor_descriptor(
            AMKBlockDesc{},
            make_tuple(make_unmerge_transform(make_tuple(Number<MwaveRepeat>{},
                                                         Number<MWaves>{},
                                                         Number<MmmacRepeat>{},
                                                         Number<MPerMmac>{},
                                                         Number<MmmacInterleave>{})),
                       make_pass_through_transform(Number<KPerBlock>{})),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<0, 1, 2, 3, 4>{}, Sequence<5>{}));
    }

    __host__ __device__ static constexpr auto MakeBBlockDescriptor_N0_N1_N2_N3_N4_K()
    {
        return transform_tensor_descriptor(
            BNKBlockDesc{},
            make_tuple(make_unmerge_transform(make_tuple(Number<NwaveRepeat>{},
                                                         Number<NWaves>{},
                                                         Number<NmmacRepeat>{},
                                                         Number<NPerMmac>{},
                                                         Number<NmmacInterleave>{})),
                       make_pass_through_transform(Number<KPerBlock>{})),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<0, 1, 2, 3, 4>{}, Sequence<5>{}));
    }

    __host__ __device__ BlockwiseGemmASmemBSmemCReg_mmac_tn_mk_nk_mn_v2()
    {
        static_assert(AMKBlockDesc::IsKnownAtCompileTime() && BNKBlockDesc::IsKnownAtCompileTime(),
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

    __host__ __device__ static constexpr auto GetCThreadDescriptorRawToInterleaved12D()
    {
        constexpr auto c_thread_desc_raw = GetCThreadDescriptorRaw12D();

        constexpr auto c_m_n0_n1_n2_lens = mmac_gemm.GetCMN0N1N2ThreadBlkLengths();

        constexpr auto num_groups_per_blk = c_m_n0_n1_n2_lens[I1];
        constexpr auto group_size         = c_m_n0_n1_n2_lens[I3];

        if constexpr(TransposeC)
        {
            constexpr auto c_thread_desc_raw_to_interleaved = transform_tensor_descriptor(
                c_thread_desc_raw,
                make_tuple(make_pass_through_transform(Number<MwaveRepeat>{}),
                           make_pass_through_transform(Number<NwaveRepeat>{}),
                           make_pass_through_transform(I1),
                           make_pass_through_transform(I1),
                           make_pass_through_transform(Number<MmmacRepeat>{}),
                           make_pass_through_transform(Number<NmmacRepeat>{}),
                           make_pass_through_transform(Number<num_groups_per_blk>{}),
                           make_pass_through_transform(I1),
                           make_pass_through_transform(Number<group_size>{}),
                           make_pass_through_transform(Number<MmmacInterleave>{}),
                           make_pass_through_transform(I1),
                           make_pass_through_transform(Number<NmmacInterleave>{})),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2>{},
                           Sequence<3>{},
                           Sequence<4>{},
                           Sequence<5>{},
                           Sequence<8>{},
                           Sequence<9>{},
                           Sequence<10>{},
                           Sequence<6>{},
                           Sequence<11>{},
                           Sequence<7>{}),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2>{},
                           Sequence<3>{},
                           Sequence<4>{},
                           Sequence<5>{},
                           Sequence<6>{},
                           Sequence<7>{},
                           Sequence<8>{},
                           Sequence<9>{},
                           Sequence<10>{},
                           Sequence<11>{}));

            return c_thread_desc_raw_to_interleaved;
        }
        else
        {
            constexpr auto c_thread_desc_raw_to_interleaved = transform_tensor_descriptor(
                c_thread_desc_raw,
                make_tuple(make_pass_through_transform(Number<MwaveRepeat>{}),
                           make_pass_through_transform(Number<NwaveRepeat>{}),
                           make_pass_through_transform(I1),
                           make_pass_through_transform(I1),
                           make_pass_through_transform(Number<MmmacRepeat>{}),
                           make_pass_through_transform(Number<NmmacRepeat>{}),
                           make_pass_through_transform(I1),
                           make_pass_through_transform(Number<MmmacInterleave>{}),
                           make_pass_through_transform(Number<num_groups_per_blk>{}),
                           make_pass_through_transform(I1),
                           make_pass_through_transform(Number<group_size>{}),
                           make_pass_through_transform(Number<NmmacInterleave>{})),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2>{},
                           Sequence<3>{},
                           Sequence<4>{},
                           Sequence<5>{},
                           Sequence<8>{},
                           Sequence<6>{},
                           Sequence<9>{},
                           Sequence<10>{},
                           Sequence<11>{},
                           Sequence<7>{}),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2>{},
                           Sequence<3>{},
                           Sequence<4>{},
                           Sequence<5>{},
                           Sequence<6>{},
                           Sequence<7>{},
                           Sequence<8>{},
                           Sequence<9>{},
                           Sequence<10>{},
                           Sequence<11>{}));

            return c_thread_desc_raw_to_interleaved;
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

        a_thread_copy_.Run(a_block_desc_m0_m1_m2_m3_m4_k,
                           make_tuple(I0, I0, I0, I0, I0, I0),
                           a_block_buf,
                           a_thread_desc_,
                           make_tuple(I0, I0, I0, I0, I0, I0),
                           a_thread_buf_);

        b_thread_copy_.Run(b_block_desc_n0_n1_n2_n3_n4_k,
                           make_tuple(I0, I0, I0, I0, I0, I0),
                           b_block_buf,
                           b_thread_desc_,
                           make_tuple(I0, I0, I0, I0, I0, I0),
                           b_thread_buf_);
    }

    template <typename CThreadBuffer>
    __device__ void Mmac(CThreadBuffer& c_thread_buf) const
    {
        using SpaceFillingCurve = SpaceFillingCurve<Sequence<MwaveRepeat,
                                                             NwaveRepeat,
                                                             MmmacRepeat,
                                                             NmmacRepeat,
                                                             MmmacInterleave,
                                                             NmmacInterleave>,
                                                    Sequence<0, 1, 2, 3, 4, 5>,
                                                    Sequence<1, 1, 1, 1, 1, 1>>;

        constexpr auto num_access = SpaceFillingCurve::GetNumOfAccess();

        static_for<0, num_access, 1>{}([&](auto access_id) {
            constexpr auto idx = SpaceFillingCurve::GetIndex(access_id);

            constexpr auto m_wave_repeat     = idx.At(Number<0>{});
            constexpr auto n_wave_repeat     = idx.At(Number<1>{});
            constexpr auto m_mmac_repeat     = idx.At(Number<2>{});
            constexpr auto n_mmac_repeat     = idx.At(Number<3>{});
            constexpr auto m_mmac_interleave = idx.At(Number<4>{});
            constexpr auto n_mmac_interleave = idx.At(Number<5>{});

            using mmac_a_input_type = typename vector_type<AStorageType, mmac_gemm.K1PerMmac>::type;
            using mmac_b_input_type = typename vector_type<BStorageType, mmac_gemm.K1PerMmac>::type;

            vector_type<AStorageType, KPack> a_thread_vec;
            vector_type<BStorageType, KPack> b_thread_vec;

            constexpr index_t c_offset =
                c_thread_desc_.CalculateOffset(make_tuple(m_wave_repeat,
                                                          n_wave_repeat,
                                                          m_mmac_repeat,
                                                          n_mmac_repeat,
                                                          m_mmac_interleave,
                                                          n_mmac_interleave,
                                                          I0));

            static_for<0, KPerThread, KPack>{}([&](auto k) {
                static_for<0, KPack, 1>{}([&](auto i) {
                    a_thread_vec.template AsType<AStorageType>()(i) =
                        a_thread_buf_[Number<a_thread_desc_.CalculateOffset(make_tuple(
                            m_wave_repeat, 0, m_mmac_repeat, 0, m_mmac_interleave, k + i))>{}];
                    b_thread_vec.template AsType<AStorageType>()(i) =
                        b_thread_buf_[Number<b_thread_desc_.CalculateOffset(make_tuple(
                            n_wave_repeat, 0, n_mmac_repeat, 0, n_mmac_interleave, k + i))>{}];
                });

                mmac_gemm.Run(a_thread_vec.template AsType<mmac_a_input_type>(),
                                       b_thread_vec.template AsType<mmac_b_input_type>(),
                                       c_thread_buf.GetVectorTypeReference(Number<c_offset>{}));
            });
        });
    }

    static constexpr auto a_block_desc_m0_m1_m2_m3_m4_k = MakeABlockDescriptor_M0_M1_M2_M3_M4_K();
    static constexpr auto b_block_desc_n0_n1_n2_n3_n4_k = MakeBBlockDescriptor_N0_N1_N2_N3_N4_K();

    protected:
    // A[M0, M1, M2, M3, M4, KPerThread]
    static constexpr auto a_thread_desc_ =
        make_naive_tensor_descriptor_packed(make_tuple(Number<MwaveRepeat>{},
                                                       I1,
                                                       Number<MmmacRepeat>{},
                                                       I1,
                                                       Number<MmmacInterleave>{},
                                                       Number<KPerThread>{}));

    // B[N0, N1, N2, N3, N4, KPerThread]
    static constexpr auto b_thread_desc_ =
        make_naive_tensor_descriptor_packed(make_tuple(Number<NwaveRepeat>{},
                                                       I1,
                                                       Number<NmmacRepeat>{},
                                                       I1,
                                                       Number<NmmacInterleave>{},
                                                       Number<KPerThread>{}));

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
        decltype(a_block_desc_m0_m1_m2_m3_m4_k),
        decltype(a_thread_desc_),
        Sequence<MwaveRepeat, 1, MmmacRepeat, 1, MmmacInterleave, KPerThread>,
        Sequence<0, 1, 2, 3, 4, 5>,
        5,
        KPack>;

    using BThreadCopy = ThreadwiseTensorSliceTransfer_SwizzledLds2Vgpr<
        BStorageType,
        BStorageType,
        decltype(b_block_desc_n0_n1_n2_n3_n4_k),
        decltype(b_thread_desc_),
        Sequence<NwaveRepeat, 1, NmmacRepeat, 1, NmmacInterleave, KPerThread>,
        Sequence<0, 1, 2, 3, 4, 5>,
        5,
        KPack>;

    AThreadCopy a_thread_copy_{CalculateAThreadOriginDataIndex_M0_M1_M2_M3_M4_K()};
    BThreadCopy b_thread_copy_{CalculateBThreadOriginDataIndex_N0_N1_N2_N3_N4_K()};

    StaticBuffer<AddressSpaceEnum::Vgpr, AStorageType, a_thread_desc_.GetElementSpaceSize(), true>
        a_thread_buf_;

    StaticBuffer<AddressSpaceEnum::Vgpr, AStorageType, b_thread_desc_.GetElementSpaceSize(), true>
        b_thread_buf_;

    StaticBufferTupleOfVector<AddressSpaceEnum::Vgpr,
                              AccDataType,
                              MwaveRepeat * NwaveRepeat * mmac_gemm.GetNumMmac(),
                              mmac_gemm.GetRegSizePerMmac(),
                              true>
        c_thread_buf_;
};

} // namespace ck
