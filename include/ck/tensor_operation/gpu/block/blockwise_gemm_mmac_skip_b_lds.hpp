// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck/utility/common_header.hpp"
#include "ck/tensor_operation/gpu/thread/threadwise_tensor_slice_transfer.hpp"
#include "ck/tensor_operation/gpu/warp/mmac_gemm.hpp"
#include "ck/tensor_description/tensor_adaptor.hpp"

namespace ck {

template <index_t BlockSize,
          typename ADataType,
          typename BDataType,
          typename AccDataType,
          typename AK0MK1BlockDesc,
          typename BK0K0BN0N1N2N3K1BlockDesc,
          index_t MPerBlock,
          index_t NPerBlock,
          index_t K0PerBlock,
          index_t MPerMmac,
          index_t NPerMmac,
          index_t MRepeat,
          index_t NRepeat,
          index_t KPack>
struct BlockwiseGemmMmac_k0mk1_k0nk1_m0n0m1n1m2n2n3n4_v1r1
{
    static constexpr auto I0 = Number<0>{};
    static constexpr auto I1 = Number<1>{};
    static constexpr auto I2 = Number<2>{};
    static constexpr auto I3 = Number<3>{};

    static constexpr index_t WaveSize = 64;

    static constexpr index_t KPerBlock = K0PerBlock * KPack;

    static constexpr index_t A_K0 = AK0MK1BlockDesc{}.GetLength(I0);
    static constexpr index_t A_K1 = AK0MK1BlockDesc{}.GetLength(I2);

    static constexpr auto mmac_gemm =
        MmacGemm<ADataType, BDataType, MPerMmac, NPerMmac, KPerBlock, KPack>{};

    static constexpr index_t KPerThread  = KPerBlock / mmac_gemm.K0PerMmac;
    static constexpr index_t K0PerThread = K0PerBlock / mmac_gemm.K0PerMmac;

    static constexpr index_t MWaves = MPerBlock / (MRepeat * MPerMmac);
    static constexpr index_t NWaves = NPerBlock / (NRepeat * NPerMmac);

    StaticBufferTupleOfVector<AddressSpaceEnum::Vgpr,
                              AccDataType,
                              MRepeat * NRepeat,
                              mmac_gemm.GetRegSizePerMmac(),
                              true>
        c_thread_buf_;

    __host__ __device__ constexpr auto& GetCThreadBuffer() { return c_thread_buf_; }

    __device__ static auto GetWaveIdx()
    {
        const index_t thread_id = get_thread_local_1d_id();

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

    __host__ __device__ BlockwiseGemmMmac_k0mk1_k0nk1_m0n0m1n1m2n2n3n4_v1r1()
    {
        static_assert(AK0MK1BlockDesc::IsKnownAtCompileTime() &&
                          BK0K0BN0N1N2N3K1BlockDesc::IsKnownAtCompileTime(),
                      "wrong! Desc should be known at compile-time");

        static_assert(BlockSize == MWaves * NWaves * WaveSize,
                      "BlockSize != MWaves * NWaves * WaveSize\n");

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

    __device__ void MoveABlockSliceWindow()
    {
        a_thread_copy_.MoveSrcSliceWindow(a_block_desc_m0_m1_m2_k,
                                          make_multi_index(0, 0, 0, K0PerBlock * KPack));
    }
    __device__ void ResetABlockStartWindow()
    {
        a_thread_copy_.SetSrcCoord(CalculateAThreadOriginDataIndex());
    }

    static constexpr auto a_block_desc_m0_m1_m2_k = MakeABlockDescriptor_M0_M1_M2_K();

    template <typename ABlockBuffer, typename BBlockBuffer, typename CThreadBuffer>
    __device__ void Run(const ABlockBuffer& a_block_buf,
                        const BBlockBuffer& b_thread_buf,
                        CThreadBuffer& c_thread_buf) const
    {
        auto a_thread_buf = make_static_buffer<AddressSpaceEnum::Vgpr, ADataType>(
            a_thread_desc_.GetElementSpaceSize());

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
                static_for<0, KPerThread, KPack>{}([&](auto k) {
                    vector_type<ADataType, KPack> a_thread_vec;
                    vector_type<BDataType, KPack> b_thread_vec;
                    constexpr index_t k0 = k / KPack;
                    static_for<0, KPack, 1>{}([&](auto i) {
                        a_thread_vec.template AsType<ADataType>()(i) = a_thread_buf
                            [Number<a_thread_desc_.CalculateOffset(make_tuple(0, 0, 0, k + i))>{}];
                        b_thread_vec.template AsType<BDataType>()(i) = b_thread_buf
                            [Number<b_thread_desc_.CalculateOffset(make_tuple(k0, n0, i))>{}];
                    });

                    using mmac_a_input_type =
                        typename vector_type<ADataType, mmac_gemm.K1PerMmac>::type;
                    using mmac_b_input_type =
                        typename vector_type<BDataType, mmac_gemm.K1PerMmac>::type;

                    constexpr index_t c_offset =
                        c_thread_desc_.CalculateOffset(make_tuple(m0, n0, 0));

                    mmac_gemm.Run(a_thread_vec.template AsType<mmac_a_input_type>(),
                                           b_thread_vec.template AsType<mmac_b_input_type>(),
                                           c_thread_buf.GetVectorTypeReference(Number<c_offset>{}));
                });
            });
        });
    }

    private:
    // A[M0, M1, M2, KPerThread]
    static constexpr auto a_thread_desc_ =
        make_naive_tensor_descriptor_packed(make_tuple(I1, I1, I1, Number<KPerThread>{}));

    // B[N0, N1, N2, KPerThread]
    static constexpr auto b_thread_desc_ =
        make_naive_tensor_descriptor_packed(make_tuple(Number<K0PerThread>{}, // KPerThread
                                                       Number<NRepeat>{},     // repeat
                                                       Number<KPack>{}));

    // C[M, N, NumRegXdlops]
    static constexpr auto c_thread_desc_ = make_naive_tensor_descriptor_packed(
        make_tuple(Number<MRepeat>{}, Number<NRepeat>{}, mmac_gemm.GetRegSizePerMmac()));

    using AThreadCopy = ThreadwiseTensorSliceTransfer_v4<ADataType,
                                                         ADataType,
                                                         decltype(a_block_desc_m0_m1_m2_k),
                                                         decltype(a_thread_desc_),
                                                         Sequence<1, 1, 1, KPerThread>,
                                                         Sequence<0, 1, 2, 3>,
                                                         3,
                                                         A_K1,
                                                         A_K1>;

    AThreadCopy a_thread_copy_{CalculateAThreadOriginDataIndex()};
};

} // namespace ck
