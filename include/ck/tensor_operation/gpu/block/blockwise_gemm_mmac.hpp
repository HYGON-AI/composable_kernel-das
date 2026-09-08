// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Info Technologies Ltd.

#pragma once

#include "ck/utility/common_header.hpp"
#include "ck/tensor_operation/gpu/thread/threadwise_tensor_slice_transfer.hpp"
#include "ck/tensor_operation/gpu/warp/mmac_gemm.hpp"
#include "ck/tensor_description/tensor_adaptor.hpp"
#include "ck/utility/loop_scheduler.hpp"

namespace ck {

template <index_t MNXdlPerWave, index_t MNWaves, index_t MNPerXdl, typename TileDesc_K0_MN_K1>
__host__ __device__ static constexpr auto
MakeGemmMmaTileDescriptor_MN0_MN1_MN2_K(const TileDesc_K0_MN_K1&)
{
    constexpr index_t K0 = TileDesc_K0_MN_K1{}.GetLength(Number<0>{});
    constexpr index_t K1 = TileDesc_K0_MN_K1{}.GetLength(Number<2>{});

    return transform_tensor_descriptor(
        TileDesc_K0_MN_K1{},
        make_tuple(make_merge_transform_v3_division_mod(make_tuple(Number<K0>{}, Number<K1>{})),
                   make_unmerge_transform(
                       make_tuple(Number<MNXdlPerWave>{}, Number<MNWaves>{}, Number<MNPerXdl>{}))),
        make_tuple(Sequence<0, 2>{}, Sequence<1>{}),
        make_tuple(Sequence<3>{}, Sequence<0, 1, 2>{}));
}

// FIXME: when transposeC = true, it's actually BlockwiseGemmMmac_k0mk1_k0nk1_m0n0m1n1m2m3m4n2_v1
template <index_t BlockSize,
          typename ADataType,
          typename BDataType,
          typename AccDataType,
          typename AK0MK1BlockDesc,
          typename BK0NK1BlockDesc,
          index_t MPerMmac,
          index_t NPerMmac,
          index_t MRepeat,
          index_t NRepeat,
          index_t KPack,
          bool TransposeC = false>
struct BlockwiseGemmMmac_k0mk1_k0nk1_m0n0m1n1m2n2n3n4_v1
{
    static constexpr auto I0 = Number<0>{};
    static constexpr auto I1 = Number<1>{};
    static constexpr auto I2 = Number<2>{};
    static constexpr auto I3 = Number<3>{};

    using ThisThreadBlock = ThisThreadBlock<BlockSize>;

    static constexpr index_t WaveSize = get_warp_size();

    static constexpr index_t MPerBlock = AK0MK1BlockDesc{}.GetLength(I1);
    static constexpr index_t NPerBlock = BK0NK1BlockDesc{}.GetLength(I1);
    static constexpr index_t KPerBlock =
        BK0NK1BlockDesc{}.GetLength(I0) * BK0NK1BlockDesc{}.GetLength(I2);

    static constexpr index_t A_K0 = AK0MK1BlockDesc{}.GetLength(I0);
    static constexpr index_t B_K0 = BK0NK1BlockDesc{}.GetLength(I0);
    static constexpr index_t A_K1 = AK0MK1BlockDesc{}.GetLength(I2);
    static constexpr index_t B_K1 = BK0NK1BlockDesc{}.GetLength(I2);

    static constexpr auto mmac_gemm =
        MmacGemm<ADataType, BDataType, MPerMmac, NPerMmac, KPerBlock, KPack, TransposeC>{};

    static constexpr index_t KPerThread = KPerBlock / mmac_gemm.K0PerMmac;

    static constexpr index_t MWaves = MPerBlock / (MRepeat * MPerMmac);
    static constexpr index_t NWaves = NPerBlock / (NRepeat * MPerMmac);

    using AStorageType = typename storage_type<ADataType>::type;
    using BStorageType = typename storage_type<BDataType>::type;

    StaticBufferTupleOfVector<AddressSpaceEnum::Vgpr,
                              AccDataType,
                              MRepeat * NRepeat,
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

    __device__ static auto CalculateAThreadOriginDataIndex()
    {
        const auto wave_idx = GetWaveIdx();

        const auto wave_idx_m = wave_idx[I0];

        // (k, m)
        const auto mmac_a_idx = mmac_gemm.CalculateAThreadOriginDataIndex();

        // (m0, m1, m2, k)
        return make_tuple(0, wave_idx_m, mmac_a_idx[I1], KPerThread * mmac_a_idx[I0]);
    }

    __device__ static auto CalculateBThreadOriginDataIndex()
    {
        const auto wave_idx = GetWaveIdx();

        const auto wave_idx_n = wave_idx[I1];

        // (k, n)
        const auto mmac_b_idx = mmac_gemm.CalculateBThreadOriginDataIndex();

        // (n0, n1, n2, k)
        return make_tuple(0, wave_idx_n, mmac_b_idx[I1], KPerThread * mmac_b_idx[I0]);
    }

    template <index_t m0, index_t n0>
    __device__ static auto CalculateCThreadOriginDataIndex(Number<m0>, Number<n0>)
    {
        const auto wave_idx = GetWaveIdx();

        const auto wave_idx_m = wave_idx[I0];
        const auto wave_idx_n = wave_idx[I1];

        const auto blk_idx = mmac_gemm.GetBeginOfThreadBlk();

        constexpr auto mrepeat_mwave_mpermmac_to_m_adaptor = make_single_stage_tensor_adaptor(
            make_tuple(make_unmerge_transform(make_tuple(MRepeat, MWaves, MPerMmac))),
            make_tuple(Sequence<0>{}),
            make_tuple(Sequence<0, 1, 2>{}));

        constexpr auto nrepeat_nwave_npermmac_to_n_adaptor = make_single_stage_tensor_adaptor(
            make_tuple(make_unmerge_transform(make_tuple(NRepeat, NWaves, NPerMmac))),
            make_tuple(Sequence<0>{}),
            make_tuple(Sequence<0, 1, 2>{}));

        const index_t c_thread_m = mrepeat_mwave_mpermmac_to_m_adaptor.CalculateBottomIndex(
            make_tuple(m0, wave_idx_m, blk_idx[I0]))[I0];
        const index_t c_thread_n = nrepeat_nwave_npermmac_to_n_adaptor.CalculateBottomIndex(
            make_tuple(n0, wave_idx_n, blk_idx[I1]))[I0];

        return make_tuple(c_thread_m, c_thread_n);
    }

    template <index_t m0, index_t n0>
    __device__ static auto CalculateCThreadOriginDataIndex8D(Number<m0>, Number<n0>)
    {
        const auto wave_idx = GetWaveIdx();

        const auto wave_idx_m = wave_idx[I0];
        const auto wave_idx_n = wave_idx[I1];

        // transposeC: m2, m3, m4, n2, no-transposeC: m2, n2, n3, n4
        const auto blk_idx = mmac_gemm.GetBeginOfThreadBlk4D();

        return make_tuple(Number<m0>{},
                          Number<n0>{},
                          wave_idx_m,
                          wave_idx_n,
                          blk_idx[I0],
                          blk_idx[I1],
                          blk_idx[I2],
                          blk_idx[I3]);
    }

    __host__ __device__ BlockwiseGemmMmac_k0mk1_k0nk1_m0n0m1n1m2n2n3n4_v1()
    {
        static_assert(AK0MK1BlockDesc::IsKnownAtCompileTime() &&
                          BK0NK1BlockDesc::IsKnownAtCompileTime(),
                      "wrong! Desc should be known at compile-time");

        static_assert(ThisThreadBlock::GetNumOfThread() == MWaves * NWaves * WaveSize,
                      "ThisThreadBlock::GetNumOfThread() != MWaves * NWaves * WaveSize\n");

        static_assert(MPerBlock % (MPerMmac * MRepeat) == 0 &&
                          NPerBlock % (NPerMmac * NRepeat) == 0,
                      "wrong!");
    }

    // threadwise mmac C output layout
    __host__ __device__ static constexpr auto GetCThreadDescriptor_M0_N0_M1_N1_M2_N2_N3_N4()
    {
        constexpr auto c_m_n0_n1_n2_lens = mmac_gemm.GetCMN0N1N2ThreadBlkLengths();

        constexpr auto M  = c_m_n0_n1_n2_lens[I0];
        constexpr auto N0 = c_m_n0_n1_n2_lens[I1];
        constexpr auto N1 = c_m_n0_n1_n2_lens[I2];
        constexpr auto N2 = c_m_n0_n1_n2_lens[I3];

        return make_naive_tensor_descriptor_packed(
            make_tuple(Number<MRepeat>{}, Number<NRepeat>{}, I1, I1, M, N0, N1, N2));
    }

    // transposed threadwise mmac C output layout
    __host__ __device__ static constexpr auto GetCThreadDescriptor_M0_N0_M1_N1_M2_M3_M4_N2()
    {
        constexpr auto c_m_n0_n1_n2_lens = mmac_gemm.GetCMN0N1N2ThreadBlkLengths();

        constexpr auto N  = c_m_n0_n1_n2_lens[I0];
        constexpr auto M0 = c_m_n0_n1_n2_lens[I1];
        constexpr auto M1 = c_m_n0_n1_n2_lens[I2];
        constexpr auto M2 = c_m_n0_n1_n2_lens[I3];

        return make_naive_tensor_descriptor_packed(
            make_tuple(Number<MRepeat>{}, Number<NRepeat>{}, I1, I1, M0, M1, M2, N));
    }

    // TODO: Grouped C thread desc ?

    // blockwise mmac C output layout
    __host__ __device__ static constexpr auto GetCBlockDescriptor_M0_N0_M1_N1_M2_N2_N3_N4()
    {
        constexpr auto c_block_desc_m0_n0_m1_n1_m2_n2 =
            make_naive_tensor_descriptor_packed(make_tuple(Number<MRepeat>{},
                                                           Number<NRepeat>{},
                                                           Number<MWaves>{},
                                                           Number<NWaves>{},
                                                           Number<MPerMmac>{},
                                                           Number<NPerMmac>{}));
        return mmac_gemm.MakeCDescriptor_M0_N0_M1_N1_M2_N2_N3_N4(c_block_desc_m0_n0_m1_n1_m2_n2);
    }

    // tranposed blockwise mmac C output layout
    __host__ __device__ static constexpr auto GetCBlockDescriptor_M0_N0_M1_N1_M2_M3_M4_N2()
    {
        constexpr auto c_block_desc_m0_n0_m1_n1_m2_n2 =
            make_naive_tensor_descriptor_packed(make_tuple(Number<MRepeat>{},
                                                           Number<NRepeat>{},
                                                           Number<MWaves>{},
                                                           Number<NWaves>{},
                                                           Number<MPerMmac>{},
                                                           Number<NPerMmac>{}));
        return mmac_gemm.MakeCDescriptor_M0_N0_M1_N1_M2_M3_M4_N2(c_block_desc_m0_n0_m1_n1_m2_n2);
    }

    // TODO: Grouped C block desc ?

    // gridwise mmac C output layout
    template <typename CGridDesc_M_N>
    __host__ __device__ static constexpr auto
    MakeCGridDescriptor_M0_N0_M1_N1_M2_N2_N3_N4(const CGridDesc_M_N& c_grid_desc_m_n)
    {
        const auto M = c_grid_desc_m_n.GetLength(I0);
        const auto N = c_grid_desc_m_n.GetLength(I1);

        // MBlocks * MRepeat -> M0
        // NBlocks * NRepeat -> N0
        const auto c_grid_desc_m0_n0_m1_n1_m2_n2 = transform_tensor_descriptor(
            c_grid_desc_m_n,
            make_tuple(
                make_unmerge_transform(make_tuple(M / (MWaves * MPerMmac), MWaves, MPerMmac)),
                make_unmerge_transform(make_tuple(N / (NWaves * NPerMmac), NWaves, NPerMmac))),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<0, 2, 4>{}, Sequence<1, 3, 5>{}));

        return mmac_gemm.MakeCDescriptor_M0_N0_M1_N1_M2_N2_N3_N4(c_grid_desc_m0_n0_m1_n1_m2_n2);
    }

    // transposed gridwise mmac C output layout
    template <typename CGridDesc_M_N>
    __host__ __device__ static constexpr auto
    MakeCGridDescriptor_M0_N0_M1_N1_M2_M3_M4_N2(const CGridDesc_M_N& c_grid_desc_m_n)
    {
        const auto M = c_grid_desc_m_n.GetLength(I0);
        const auto N = c_grid_desc_m_n.GetLength(I1);

        // MBlocks * MRepeat -> M0
        // NBlocks * NRepeat -> N0
        const auto c_grid_desc_m0_n0_m1_n1_m2_n2 = transform_tensor_descriptor(
            c_grid_desc_m_n,
            make_tuple(
                make_unmerge_transform(make_tuple(M / (MWaves * MPerMmac), MWaves, MPerMmac)),
                make_unmerge_transform(make_tuple(N / (NWaves * NPerMmac), NWaves, NPerMmac))),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<0, 2, 4>{}, Sequence<1, 3, 5>{}));

        return mmac_gemm.MakeCDescriptor_M0_N0_M1_N1_M2_M3_M4_N2(c_grid_desc_m0_n0_m1_n1_m2_n2);
    }

    // TODO: Grouped C grid desc ?

    __host__ __device__ static constexpr auto MakeABlockDescriptor_M0_M1_M2_K()
    {
        return transform_tensor_descriptor(
            AK0MK1BlockDesc{},
            make_tuple(
                make_merge_transform_v3_division_mod(make_tuple(Number<A_K0>{}, Number<A_K1>{})),
                make_unmerge_transform(
                    make_tuple(Number<MRepeat>{}, Number<MWaves>{}, Number<MPerMmac>{}))),
            make_tuple(Sequence<0, 2>{}, Sequence<1>{}),
            make_tuple(Sequence<3>{}, Sequence<0, 1, 2>{}));
    }

    __host__ __device__ static constexpr auto MakeBBlockDescriptor_N0_N1_N2_K()
    {
        return transform_tensor_descriptor(
            BK0NK1BlockDesc{},
            make_tuple(
                make_merge_transform_v3_division_mod(make_tuple(Number<B_K0>{}, Number<B_K1>{})),
                make_unmerge_transform(
                    make_tuple(Number<NRepeat>{}, Number<NWaves>{}, Number<NPerMmac>{}))),
            make_tuple(Sequence<0, 2>{}, Sequence<1>{}),
            make_tuple(Sequence<3>{}, Sequence<0, 1, 2>{}));
    }

    static constexpr auto a_block_desc_m0_m1_m2_k = MakeABlockDescriptor_M0_M1_M2_K();
    static constexpr auto b_block_desc_n0_n1_n2_k = MakeBBlockDescriptor_N0_N1_N2_K();

    template <typename ABlockBuffer, typename BBlockBuffer, typename CThreadBuffer>
    __device__ void Run(const ABlockBuffer& a_block_buf,
                        const BBlockBuffer& b_block_buf,
                        CThreadBuffer& c_thread_buf) const
    {
        auto a_thread_buf = make_static_buffer<AddressSpaceEnum::Vgpr, AStorageType>(
            a_thread_desc_.GetElementSpaceSize());
        auto b_thread_buf = make_static_buffer<AddressSpaceEnum::Vgpr, BStorageType>(
            b_thread_desc_.GetElementSpaceSize());

        static_for<0, MRepeat, 1>{}([&](auto m0) {
            // read A
            a_thread_copy_.Run(a_block_desc_m0_m1_m2_k,
                               make_tuple(m0, I0, I0, I0),
                               a_block_buf,
                               a_thread_desc_,
                               make_tuple(I0, I0, I0, I0),
                               a_thread_buf);

            static_for<0, NRepeat, 1>{}([&](auto n0) {
                // read B
                b_thread_copy_.Run(b_block_desc_n0_n1_n2_k,
                                   make_tuple(n0, I0, I0, I0),
                                   b_block_buf,
                                   b_thread_desc_,
                                   make_tuple(I0, I0, I0, I0),
                                   b_thread_buf);

                static_for<0, KPerThread, KPack>{}([&](auto k) {
                    vector_type<AStorageType, KPack> a_thread_vec;
                    vector_type<BStorageType, KPack> b_thread_vec;

                    static_for<0, KPack, 1>{}([&](auto i) {
                        a_thread_vec.template AsType<AStorageType>()(i) = a_thread_buf
                            [Number<a_thread_desc_.CalculateOffset(make_tuple(0, 0, 0, k + i))>{}];
                        b_thread_vec.template AsType<BStorageType>()(i) = b_thread_buf
                            [Number<b_thread_desc_.CalculateOffset(make_tuple(0, 0, 0, k + i))>{}];
                    });

                    using mmac_a_input_type =
                        typename vector_type<AStorageType, mmac_gemm.K1PerMmac>::type;

                    using mmac_b_input_type =
                        typename vector_type<BStorageType, mmac_gemm.K1PerMmac>::type;

                    constexpr index_t c_offset =
                        c_thread_desc_.CalculateOffset(make_tuple(m0, n0, 0));

                    mmac_gemm.Run(a_thread_vec.template AsType<mmac_a_input_type>(),
                                           b_thread_vec.template AsType<mmac_b_input_type>(),
                                           c_thread_buf.GetVectorTypeReference(Number<c_offset>{}));
                });
            });
        });
    }

    protected:
    // A[M0, M1, M2, KPerThread]
    static constexpr auto a_thread_desc_ =
        make_naive_tensor_descriptor_packed(make_tuple(I1, I1, I1, Number<KPerThread>{}));

    // B[N0, N1, N2, KPerThread]
    static constexpr auto b_thread_desc_ =
        make_naive_tensor_descriptor_packed(make_tuple(I1, I1, I1, Number<KPerThread>{}));

    // C[M, N, NumRegXdlops]
    static constexpr auto c_thread_desc_ = make_naive_tensor_descriptor_packed(
        make_tuple(Number<MRepeat>{}, Number<NRepeat>{}, mmac_gemm.GetRegSizePerMmac()));

    // no element op, so we directly pass storage type here
    using AThreadCopy = ThreadwiseTensorSliceTransfer_v4<AStorageType,
                                                         AStorageType,
                                                         decltype(a_block_desc_m0_m1_m2_k),
                                                         decltype(a_thread_desc_),
                                                         Sequence<1, 1, 1, KPerThread>,
                                                         Sequence<0, 1, 2, 3>,
                                                         3,
                                                         A_K1,
                                                         A_K1>;

    using BThreadCopy = ThreadwiseTensorSliceTransfer_v4<BStorageType,
                                                         BStorageType,
                                                         decltype(b_block_desc_n0_n1_n2_k),
                                                         decltype(b_thread_desc_),
                                                         Sequence<1, 1, 1, KPerThread>,
                                                         Sequence<0, 1, 2, 3>,
                                                         3,
                                                         B_K1,
                                                         B_K1>;

    AThreadCopy a_thread_copy_{CalculateAThreadOriginDataIndex()};
    BThreadCopy b_thread_copy_{CalculateBThreadOriginDataIndex()};
};

// Note: To facilitate the inter-wave loop scheduler, we need to explicitly set the macro
// CK_EXPERIMENTAL_INTER_WAVE_SCHEDULING=1 as a few intrinsics are not yet available in
// the latest ROCm release. For unsupported compilers, inter-wave loop scheduler falls back to the
// default loop scheduler which is given by the macro CK_EXPERIMENTAL_INTER_WAVE_SCHEDULING=0
template <index_t BlockSize,
          typename ADataType,
          typename BDataType,
          typename AccDataType,
          typename AK0MK1BlockDesc,
          typename BK0NK1BlockDesc,
          index_t MPerMmac,
          index_t NPerMmac,
          index_t MRepeat,
          index_t NRepeat,
          index_t KPack,
          bool TransposeC        = false,
          index_t NumMacClusters = CK_EXPERIMENTAL_INTER_WAVE_SCHEDULING_MAC_CLUSTERS>
struct BlockwiseGemmMmacInterwave_k0mk1_k0nk1_m0n0m1n1m2n2n3n4_v1
    : public BlockwiseGemmMmac_k0mk1_k0nk1_m0n0m1n1m2n2n3n4_v1<BlockSize,
                                                               ADataType,
                                                               BDataType,
                                                               AccDataType,
                                                               AK0MK1BlockDesc,
                                                               BK0NK1BlockDesc,
                                                               MPerMmac,
                                                               NPerMmac,
                                                               MRepeat,
                                                               NRepeat,
                                                               KPack,
                                                               TransposeC>
{

    using AStorageType = typename storage_type<ADataType>::type;
    using BStorageType = typename storage_type<BDataType>::type;

    using Base = BlockwiseGemmMmac_k0mk1_k0nk1_m0n0m1n1m2n2n3n4_v1<BlockSize,
                                                                   ADataType,
                                                                   BDataType,
                                                                   AccDataType,
                                                                   AK0MK1BlockDesc,
                                                                   BK0NK1BlockDesc,
                                                                   MPerMmac,
                                                                   NPerMmac,
                                                                   MRepeat,
                                                                   NRepeat,
                                                                   KPack,
                                                                   TransposeC>;

#if CK_EXPERIMENTAL_INTER_WAVE_SCHEDULING
    using Base::a_block_desc_m0_m1_m2_k;
    using Base::A_K1;
    using Base::b_block_desc_n0_n1_n2_k;
    using Base::B_K1;
    using Base::c_thread_buf_;
    using Base::c_thread_desc_;
    using Base::CalculateAThreadOriginDataIndex;
    using Base::CalculateBThreadOriginDataIndex;
    using Base::I0;
    using Base::I1;
    using Base::KPerThread;
    using Base::mmac_gemm;

    static constexpr index_t KPerInnerLoop = math::max(KPerThread / NumMacClusters, KPack);

    // 2-wave optimized blockwise gemm
    template <typename ABlockBuffer, typename BBlockBuffer, typename CThreadBuffer>
    __device__ void Run(const ABlockBuffer& a_block_buf,
                        const BBlockBuffer& b_block_buf,
                        CThreadBuffer& c_thread_buf) const
    {
        auto a_thread_buf = make_static_buffer<AddressSpaceEnum::Vgpr, AStorageType>(
            a_thread_desc_.GetElementSpaceSize());
        auto b_thread_buf = make_static_buffer<AddressSpaceEnum::Vgpr, BStorageType>(
            b_thread_desc_.GetElementSpaceSize());

        static_for<0, KPerThread, KPerInnerLoop>{}([&](auto k) {
            static_for<0, MRepeat, 1>{}([&](auto m0) {
                // read A
                a_thread_copy_.Run(a_block_desc_m0_m1_m2_k,
                                   make_tuple(m0, I0, I0, k),
                                   a_block_buf,
                                   a_thread_desc_,
                                   make_tuple(m0, I0, I0, I0),
                                   a_thread_buf);
            });
            static_for<0, NRepeat, 1>{}([&](auto n0) {
                // read B
                b_thread_copy_.Run(b_block_desc_n0_n1_n2_k,
                                   make_tuple(n0, I0, I0, k),
                                   b_block_buf,
                                   b_thread_desc_,
                                   make_tuple(n0, I0, I0, I0),
                                   b_thread_buf);
            });
            __builtin_amdgcn_sched_barrier(0);
            // NOTE: Synchronize threads in a workgroup at the start of each MAC cluster, but except
            // the first, as we can shorten non-MAC cluster a bit and there's no observable negative
            // impact. The desired effect is waves in a workgroup executing MAC in sync. This avoids
            // some out-of-sync waves hijacking MAC resource from other workgroups and reducing the
            // chance of latency hiding by waiting for the rest of the workgroup at the eventual
            // sync point.
            if constexpr(k.value != 0 || KPerInnerLoop == KPerThread)
            {
                asm volatile("s_barrier" ::);
                __builtin_amdgcn_sched_barrier(0);
            }
            static_for<0, KPerInnerLoop, KPack>{}([&](auto k_) {
                static_for<0, MRepeat, 1>{}([&](auto m0) {
                    static_for<0, NRepeat, 1>{}([&](auto n0) {
                        vector_type<AStorageType, KPack> a_thread_vec;
                        vector_type<BStorageType, KPack> b_thread_vec;

                        static_for<0, KPack, 1>{}([&](auto i) {
                            a_thread_vec.template AsType<AStorageType>()(i) =
                                a_thread_buf[Number<a_thread_desc_.CalculateOffset(
                                    make_tuple(m0, 0, 0, k_ + i))>{}];
                            b_thread_vec.template AsType<BStorageType>()(i) =
                                b_thread_buf[Number<b_thread_desc_.CalculateOffset(
                                    make_tuple(n0, 0, 0, k_ + i))>{}];
                        });

                        using mmac_a_input_type =
                            typename vector_type<AStorageType, mmac_gemm.K1PerMmac>::type;

                        using mmac_b_input_type =
                            typename vector_type<BStorageType, mmac_gemm.K1PerMmac>::type;

                        constexpr index_t c_offset =
                            c_thread_desc_.CalculateOffset(make_tuple(m0, n0, 0));

                        // The block_sync_lds() here performs double duty:
                        // A) safeguard against data hazard because barrier from blockwise_gemm is
                        // moved here B) reduce VMEM FIFO congestion by applying small delays to
                        // different wavefronts It is performed near the end of MAC cluster to
                        // minimize lgkmcnt penalty
                        if constexpr(k.value == KPerThread - KPerInnerLoop &&
                                     k_.value == KPerInnerLoop - KPack && m0.value == MRepeat - 1 &&
                                     n0.value == NRepeat - 1)
                        {
                            __builtin_amdgcn_sched_barrier(0);
                            block_sync_lds();
                            __builtin_amdgcn_sched_barrier(0);
                        }

                        mmac_gemm.Run(
                            a_thread_vec.template AsType<mmac_a_input_type>(),
                            b_thread_vec.template AsType<mmac_b_input_type>(),
                            c_thread_buf.GetVectorTypeReference(Number<c_offset>{}));
                        if constexpr(k_.value == 0 && m0.value == 0 && n0.value == 0)
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
        });
    }

    protected:
    // A[M0, M1, M2, KPerInnerLoop]
    static constexpr auto a_thread_desc_ = make_naive_tensor_descriptor_packed(
        make_tuple(Number<MRepeat>{}, I1, I1, Number<KPerInnerLoop>{}));

    // B[N0, N1, N2, KPerInnerLoop]
    static constexpr auto b_thread_desc_ = make_naive_tensor_descriptor_packed(
        make_tuple(Number<NRepeat>{}, I1, I1, Number<KPerInnerLoop>{}));

    // no element op, so we directly pass storage type here
    using AThreadCopy = ThreadwiseTensorSliceTransfer_v4<AStorageType,
                                                         AStorageType,
                                                         decltype(a_block_desc_m0_m1_m2_k),
                                                         decltype(a_thread_desc_),
                                                         Sequence<1, 1, 1, KPerInnerLoop>,
                                                         Sequence<0, 1, 2, 3>,
                                                         3,
                                                         A_K1,
                                                         A_K1>;

    using BThreadCopy = ThreadwiseTensorSliceTransfer_v4<BStorageType,
                                                         BStorageType,
                                                         decltype(b_block_desc_n0_n1_n2_k),
                                                         decltype(b_thread_desc_),
                                                         Sequence<1, 1, 1, KPerInnerLoop>,
                                                         Sequence<0, 1, 2, 3>,
                                                         3,
                                                         B_K1,
                                                         B_K1>;

    AThreadCopy a_thread_copy_{CalculateAThreadOriginDataIndex()};
    BThreadCopy b_thread_copy_{CalculateBThreadOriginDataIndex()};

#endif // #if CK_EXPERIMENTAL_INTER_WAVE_SCHEDULING
};

template <index_t BlockSize,
          typename ADataType,
          typename BDataType,
          typename AccDataType,
          typename AK0MK1BlockDesc,
          typename BK0NK1BlockDesc,
          index_t MPerMmac,
          index_t NPerMmac,
          index_t MRepeat,
          index_t NRepeat,
          index_t KPack,
          LoopScheduler LoopSched,
          bool TransposeC = false>
constexpr auto BlockwiseGemmMmac_k0mk1_k0nk1_m0n0m1n1m2n2n3n4_Selector()
{
    if constexpr(LoopSched == LoopScheduler::Default)
    {
        return BlockwiseGemmMmac_k0mk1_k0nk1_m0n0m1n1m2n2n3n4_v1<BlockSize,
                                                                 ADataType,
                                                                 BDataType,
                                                                 AccDataType,
                                                                 AK0MK1BlockDesc,
                                                                 BK0NK1BlockDesc,
                                                                 MPerMmac,
                                                                 NPerMmac,
                                                                 MRepeat,
                                                                 NRepeat,
                                                                 KPack,
                                                                 TransposeC>{};
    }
    else if constexpr(LoopSched == LoopScheduler::Interwave)
    {
        return BlockwiseGemmMmacInterwave_k0mk1_k0nk1_m0n0m1n1m2n2n3n4_v1<BlockSize,
                                                                          ADataType,
                                                                          BDataType,
                                                                          AccDataType,
                                                                          AK0MK1BlockDesc,
                                                                          BK0NK1BlockDesc,
                                                                          MPerMmac,
                                                                          NPerMmac,
                                                                          MRepeat,
                                                                          NRepeat,
                                                                          KPack,
                                                                          TransposeC>{};
    }
};

/**
 * @brief Blockwise gemm
 *
 * Supports
 * 1. regular MMAC output M2_N2_N3_N4 and transposed MMAC output M2_M3_M4_N2
 * 2. decoupled input tile descriptor and mma tile descriptor in order to support both vgpr and LDS
 * source buffer
 * 3. configurable k index starting position and step size after each mmac instruction
 */
template <
    index_t BlockSize,
    typename ADataType,
    typename BDataType,
    typename AccDataType,
    typename ATileDesc,
    typename BTileDesc,
    typename AMmaTileDesc,
    typename BMmaTileDesc,
    index_t MPerBlock,
    index_t NPerBlock,
    index_t KPerBlock,
    index_t MPerMmac,
    index_t NPerMmac,
    index_t MRepeat,
    index_t NRepeat,
    index_t KPack,
    bool TransposeC = false,
    index_t AMmaKStride =
        KPack * MmacGemm<ADataType, BDataType, MPerMmac, NPerMmac, KPerBlock, KPack, TransposeC>{}
                    .K0PerMmac,
    index_t BMmaKStride =
        KPack * MmacGemm<ADataType, BDataType, MPerMmac, NPerMmac, KPerBlock, KPack, TransposeC>{}
                    .K0PerMmac>
struct BlockwiseGemmMmac_v2
{
    static constexpr auto I0 = Number<0>{};
    static constexpr auto I1 = Number<1>{};
    static constexpr auto I2 = Number<2>{};
    static constexpr auto I3 = Number<3>{};

    using ThisThreadBlock = ThisThreadBlock<BlockSize>;

    static constexpr index_t WaveSize = get_warp_size();

    static constexpr index_t A_K1 = ATileDesc{}.GetLength(I2);
    static constexpr index_t B_K1 = BTileDesc{}.GetLength(I2);

    static constexpr auto mmac_gemm =
        MmacGemm<ADataType, BDataType, MPerMmac, NPerMmac, KPerBlock, KPack, TransposeC>{};

    // scalar
    static constexpr index_t KPerThread = KPerBlock / mmac_gemm.K0PerMmac;
    static_assert(KPerThread % KPack == 0,
                  "Wrong KPack setting; try increasing KPerThread or decreasing KPack");

    static constexpr index_t MWaves = MPerBlock / (MRepeat * MPerMmac);
    static constexpr index_t NWaves = NPerBlock / (NRepeat * NPerMmac);

    using AStorageType = typename storage_type<ADataType>::type;
    using BStorageType = typename storage_type<BDataType>::type;

    // c thread buffer
    StaticBufferTupleOfVector<AddressSpaceEnum::Vgpr,
                              AccDataType,
                              MRepeat * NRepeat,
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

    __device__ static auto CalculateAThreadOriginDataIndex()
    {
        const auto wave_idx = GetWaveIdx();

        const auto wave_idx_m = wave_idx[I0];

        // (k, m)
        const auto mmac_a_idx = mmac_gemm.CalculateAThreadOriginDataIndex();

        // (m0, m1, m2, k)
        return make_tuple(0, wave_idx_m, mmac_a_idx[I1], KPack * mmac_a_idx[I0]);
    }

    __device__ static auto CalculateBThreadOriginDataIndex()
    {
        const auto wave_idx = GetWaveIdx();

        const auto wave_idx_n = wave_idx[I1];

        // (k, n)
        const auto mmac_b_idx = mmac_gemm.CalculateBThreadOriginDataIndex();

        // (n0, n1, n2, k)
        return make_tuple(0, wave_idx_n, mmac_b_idx[I1], KPack * mmac_b_idx[I0]);
    }

    template <index_t m0, index_t n0>
    __device__ static auto CalculateCThreadOriginDataIndex(Number<m0>, Number<n0>)
    {
        const auto wave_idx = GetWaveIdx();

        const auto wave_idx_m = wave_idx[I0];
        const auto wave_idx_n = wave_idx[I1];

        const auto blk_idx = mmac_gemm.GetBeginOfThreadBlk();

        constexpr auto mrepeat_mwave_mpermmac_to_m_adaptor = make_single_stage_tensor_adaptor(
            make_tuple(make_unmerge_transform(make_tuple(MRepeat, MWaves, MPerMmac))),
            make_tuple(Sequence<0>{}),
            make_tuple(Sequence<0, 1, 2>{}));

        constexpr auto nrepeat_nwave_npermmac_to_n_adaptor = make_single_stage_tensor_adaptor(
            make_tuple(make_unmerge_transform(make_tuple(NRepeat, NWaves, NPerMmac))),
            make_tuple(Sequence<0>{}),
            make_tuple(Sequence<0, 1, 2>{}));

        const index_t c_thread_m = mrepeat_mwave_mpermmac_to_m_adaptor.CalculateBottomIndex(
            make_tuple(m0, wave_idx_m, blk_idx[I0]))[I0];
        const index_t c_thread_n = nrepeat_nwave_npermmac_to_n_adaptor.CalculateBottomIndex(
            make_tuple(n0, wave_idx_n, blk_idx[I1]))[I0];

        return make_tuple(c_thread_m, c_thread_n);
    }

    template <index_t m0, index_t n0>
    __device__ static auto CalculateCThreadOriginDataIndex8D(Number<m0>, Number<n0>)
    {
        const auto wave_idx = GetWaveIdx();

        const auto wave_idx_m = wave_idx[I0];
        const auto wave_idx_n = wave_idx[I1];

        // transposeC: m2, m3, m4, n2, no-transposeC: m2, n2, n3, n4
        const auto blk_idx = mmac_gemm.GetBeginOfThreadBlk4D();

        return make_tuple(
            m0, n0, wave_idx_m, wave_idx_n, blk_idx[I0], blk_idx[I1], blk_idx[I2], blk_idx[I3]);
    }

    using Tuple4 = decltype(CalculateAThreadOriginDataIndex());

    __host__ __device__
    BlockwiseGemmMmac_v2(Tuple4 a_src_origin = CalculateAThreadOriginDataIndex(),
                         Tuple4 b_src_origin = CalculateBThreadOriginDataIndex())
        : a_thread_copy_(a_src_origin), b_thread_copy_(b_src_origin)
    {
        static_assert(AMmaTileDesc::IsKnownAtCompileTime() && BMmaTileDesc::IsKnownAtCompileTime(),
                      "wrong! Desc should be known at compile-time");

        static_assert(ThisThreadBlock::GetNumOfThread() == MWaves * NWaves * WaveSize,
                      "ThisThreadBlock::GetNumOfThread() != MWaves * NWaves * WaveSize\n");

        static_assert(MPerBlock % (MPerMmac * MRepeat) == 0 &&
                          NPerBlock % (NPerMmac * NRepeat) == 0,
                      "wrong!");
    }

    // TODO: do we need copy constructor?

    // threadwise mmac C output layout
    __host__ __device__ static constexpr auto GetCThreadDescriptor_M0_N0_M1_N1_M2_N2_N3_N4()
    {
        constexpr auto c_m_n0_n1_n2_lens = mmac_gemm.GetCMN0N1N2ThreadBlkLengths();

        constexpr auto M  = c_m_n0_n1_n2_lens[I0];
        constexpr auto N0 = c_m_n0_n1_n2_lens[I1];
        constexpr auto N1 = c_m_n0_n1_n2_lens[I2];
        constexpr auto N2 = c_m_n0_n1_n2_lens[I3];

        return make_naive_tensor_descriptor_packed(
            make_tuple(Number<MRepeat>{}, Number<NRepeat>{}, I1, I1, M, N0, N1, N2));
    }

    // transposed threadwise mmac C' output layout
    __host__ __device__ static constexpr auto GetCThreadDescriptor_M0_N0_M1_N1_M2_M3_M4_N2()
    {
        constexpr auto c_n_m0_m1_m2_lens = mmac_gemm.GetCMN0N1N2ThreadBlkLengths();
        constexpr auto M0                = c_n_m0_m1_m2_lens[I1];
        constexpr auto M1                = c_n_m0_m1_m2_lens[I2];
        constexpr auto M2                = c_n_m0_m1_m2_lens[I3];
        constexpr auto N                 = c_n_m0_m1_m2_lens[I0];

        return make_naive_tensor_descriptor_packed(
            make_tuple(Number<MRepeat>{}, Number<NRepeat>{}, I1, I1, M0, M1, M2, N));
    }

    // TODO: Grouped C thread desc ?

    // blockwise mmac C output layout
    __host__ __device__ static constexpr auto GetCBlockDescriptor_M0_N0_M1_N1_M2_N2_N3_N4()
    {
        constexpr auto c_block_desc_m0_n0_m1_n1_m2_n2 =
            make_naive_tensor_descriptor_packed(make_tuple(Number<MRepeat>{},
                                                           Number<NRepeat>{},
                                                           Number<MWaves>{},
                                                           Number<NWaves>{},
                                                           Number<MPerMmac>{},
                                                           Number<NPerMmac>{}));
        return mmac_gemm.MakeCDescriptor_M0_N0_M1_N1_M2_N2_N3_N4(c_block_desc_m0_n0_m1_n1_m2_n2);
    }

    // transposed blockwise mmac C output layout
    __host__ __device__ static constexpr auto GetCBlockDescriptor_M0_N0_M1_N1_M2_M3_M4_N2()
    {
        constexpr auto c_block_desc_m0_n0_m1_n1_m2_n2 =
            make_naive_tensor_descriptor_packed(make_tuple(Number<MRepeat>{},
                                                           Number<NRepeat>{},
                                                           Number<MWaves>{},
                                                           Number<NWaves>{},
                                                           Number<MPerMmac>{},
                                                           Number<NPerMmac>{}));
        return mmac_gemm.MakeCDescriptor_M0_N0_M1_N1_M2_M3_M4_N2(c_block_desc_m0_n0_m1_n1_m2_n2);
    }

    // TODO: Grouped C block desc ?

    // gridwise mmac C output layout
    template <typename CGridDesc_M_N>
    __host__ __device__ static constexpr auto
    MakeCGridDescriptor_M0_N0_M1_N1_M2_N2_N3_N4(const CGridDesc_M_N& c_grid_desc_m_n)
    {
        const auto M = c_grid_desc_m_n.GetLength(I0);
        const auto N = c_grid_desc_m_n.GetLength(I1);

        // MBlocks * MRepeat -> M0
        // NBlocks * NRepeat -> N0
        const auto c_grid_desc_m0_n0_m1_n1_m2_n2 = transform_tensor_descriptor(
            c_grid_desc_m_n,
            make_tuple(
                make_unmerge_transform(make_tuple(M / (MWaves * MPerMmac), MWaves, MPerMmac)),
                make_unmerge_transform(make_tuple(N / (NWaves * NPerMmac), NWaves, NPerMmac))),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<0, 2, 4>{}, Sequence<1, 3, 5>{}));

        return mmac_gemm.MakeCDescriptor_M0_N0_M1_N1_M2_N2_N3_N4(c_grid_desc_m0_n0_m1_n1_m2_n2);
    }

    // transposed gridwise mmac C output layout
    template <typename CGridDesc_M_N>
    __host__ __device__ static constexpr auto
    MakeCGridDescriptor_M0_N0_M1_N1_M2_M3_M4_N2(const CGridDesc_M_N& c_grid_desc_m_n)
    {
        const auto M = c_grid_desc_m_n.GetLength(I0);
        const auto N = c_grid_desc_m_n.GetLength(I1);

        // MBlocks * MRepeat -> M0
        // NBlocks * NRepeat -> N0
        const auto c_grid_desc_m0_n0_m1_n1_m2_n2 = transform_tensor_descriptor(
            c_grid_desc_m_n,
            make_tuple(
                make_unmerge_transform(make_tuple(M / (MWaves * MPerMmac), MWaves, MPerMmac)),
                make_unmerge_transform(make_tuple(N / (NWaves * NPerMmac), NWaves, NPerMmac))),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<0, 2, 4>{}, Sequence<1, 3, 5>{}));

        return mmac_gemm.MakeCDescriptor_M0_N0_M1_N1_M2_M3_M4_N2(c_grid_desc_m0_n0_m1_n1_m2_n2);
    }

    // TODO: Grouped C grid desc ?

    template <typename ABlockBuffer, typename BBlockBuffer, typename CThreadBuffer>
    __device__ void Run(const ABlockBuffer& a_block_buf,
                        const BBlockBuffer& b_block_buf,
                        CThreadBuffer& c_thread_buf) const
    {
        auto a_thread_buf = make_static_buffer<AddressSpaceEnum::Vgpr, AStorageType>(
            a_thread_desc_.GetElementSpaceSize());
        auto b_thread_buf = make_static_buffer<AddressSpaceEnum::Vgpr, BStorageType>(
            b_thread_desc_.GetElementSpaceSize());

        static_for<0, KPerThread / KPack, 1>{}([&](auto k) { // k=0,1,2 instead of k=0,kpack*1, ...
            static_for<0, MRepeat, 1>{}([&](auto m0) {
                // read A
                a_thread_copy_.Run(a_block_desc_m0_m1_m2_k,
                                   make_tuple(m0, I0, I0, Number<k * AMmaKStride>{}),
                                   a_block_buf,
                                   a_thread_desc_,
                                   make_tuple(I0, I0, I0, I0),
                                   a_thread_buf);

                static_for<0, NRepeat, 1>{}([&](auto n0) {
                    // read B
                    b_thread_copy_.Run(b_block_desc_n0_n1_n2_k,
                                       make_tuple(n0, I0, I0, Number<k * BMmaKStride>{}),
                                       b_block_buf,
                                       b_thread_desc_,
                                       make_tuple(I0, I0, I0, I0),
                                       b_thread_buf);
                    vector_type<AStorageType, KPack> a_thread_vec;
                    vector_type<BStorageType, KPack> b_thread_vec;

                    static_for<0, KPack, 1>{}([&](auto i) {
                        a_thread_vec.template AsType<AStorageType>()(i) = a_thread_buf
                            [Number<a_thread_desc_.CalculateOffset(make_tuple(0, 0, 0, i))>{}];
                        b_thread_vec.template AsType<BStorageType>()(i) = b_thread_buf
                            [Number<b_thread_desc_.CalculateOffset(make_tuple(0, 0, 0, i))>{}];
                    });

                    using mmac_a_input_type =
                        typename vector_type<AStorageType, mmac_gemm.K1PerMmac>::type;
                    using mmac_b_input_type =
                        typename vector_type<BStorageType, mmac_gemm.K1PerMmac>::type;

                    constexpr index_t c_offset =
                        c_thread_desc_.CalculateOffset(make_tuple(m0, n0, 0));

                    mmac_gemm.Run(a_thread_vec.template AsType<mmac_a_input_type>(),
                                           b_thread_vec.template AsType<mmac_b_input_type>(),
                                           c_thread_buf.GetVectorTypeReference(Number<c_offset>{}));
                });
            });
        });
    }

    static constexpr AMmaTileDesc a_block_desc_m0_m1_m2_k;
    static constexpr BMmaTileDesc b_block_desc_n0_n1_n2_k;

    protected:
    // A[M0, M1, M2, KPack]
    static constexpr auto a_thread_desc_ =
        make_naive_tensor_descriptor_packed(make_tuple(I1, I1, I1, Number<KPack>{}));

    // B[N0, N1, N2, KPack]
    static constexpr auto b_thread_desc_ =
        make_naive_tensor_descriptor_packed(make_tuple(I1, I1, I1, Number<KPack>{}));

    // C[MRepeat, NRepeat, NumRegMmac]
    static constexpr auto c_thread_desc_ = make_naive_tensor_descriptor_packed(
        make_tuple(Number<MRepeat>{}, Number<NRepeat>{}, mmac_gemm.GetRegSizePerMmac()));

    // TODO: how to support fused gemm + gemm, if at least one block src is actually vgpr?
    // no element op, so we directly pass storage type here
    using AThreadCopy = ThreadwiseTensorSliceTransfer_v4<AStorageType,
                                                         AStorageType,
                                                         decltype(a_block_desc_m0_m1_m2_k),
                                                         decltype(a_thread_desc_),
                                                         Sequence<1, 1, 1, KPack>,
                                                         Sequence<0, 1, 2, 3>,
                                                         3,
                                                         A_K1,
                                                         A_K1>;

    using BThreadCopy = ThreadwiseTensorSliceTransfer_v4<BStorageType,
                                                         BStorageType,
                                                         decltype(b_block_desc_n0_n1_n2_k),
                                                         decltype(b_thread_desc_),
                                                         Sequence<1, 1, 1, KPack>,
                                                         Sequence<0, 1, 2, 3>,
                                                         3,
                                                         B_K1,
                                                         B_K1>;

    AThreadCopy a_thread_copy_;
    BThreadCopy b_thread_copy_;
};

} // namespace ck
