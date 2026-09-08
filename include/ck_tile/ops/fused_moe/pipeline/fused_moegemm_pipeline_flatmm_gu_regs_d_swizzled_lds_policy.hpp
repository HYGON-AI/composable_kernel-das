// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/fused_moe/pipeline/fused_moegemm_traits.hpp"
// #include "ck_tile/ops/flatmm.hpp"
#include "ck_tile/ops/gemm/warp/warp_mmac_gemm.hpp"
#include "ck_tile/ops/gemm/warp/warp_mmac_gemm_dispatcher.hpp"

namespace ck_tile {

struct FusedMoeGemmPipelineFlatmmGuRegsDLdsPolicy
{
    CK_TILE_HOST_DEVICE static constexpr index_t GetAsyncCopyDwords()
    {
        // TODO: always 1 dword
        return 1;
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto GetAlignment_A()
    {
        // using async
        constexpr index_t copy_bytes = 4 * Problem::AGmemLoadVectorLength; // same as ASmemStore
        constexpr index_t data_bytes = sizeof(typename Problem::ADataType);
        static_assert(copy_bytes % data_bytes == 0);
        return copy_bytes / data_bytes;
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto GetAlignment_G()
    {
        // align to load vector length
        constexpr index_t copy_bytes = [&]() { return 4 * Problem::GGmemLoadVectorLength; }();
        constexpr index_t data_bytes = sizeof(typename Problem::GDataType);
        static_assert(copy_bytes % data_bytes == 0);
        return copy_bytes / data_bytes;
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto GetAlignment_D()
    {
        constexpr index_t copy_bytes = [&]() { return 4 * Problem::DGmemLoadVectorLength; }();
        constexpr index_t data_bytes = sizeof(typename Problem::DDataType);
        static_assert(copy_bytes % data_bytes == 0);
        return copy_bytes / data_bytes;
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto GetAlignment_O()
    {
        if constexpr(Problem::Traits::OAtomic == 1)
        {
            // pack fp16/bf16 atomic
            static_assert(sizeof(typename Problem::ODataType) == 2);
            return 2;
        }
        else if constexpr(Problem::Traits::OAtomic == 2)
        {
            // fp32 atomic
            return 1;
        }
        else
        {
            return 16 / sizeof(typename Problem::ODataType);
        }
    }

    template <typename DataType_>
    CK_TILE_HOST_DEVICE static constexpr auto GetSmemKPack()
    {
        // TODO: this is for 3d layout
        return 16 / sizeof(remove_cvref_t<DataType_>);
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto GetSmemKPack_A()
    {
        return GetSmemKPack<typename Problem::ADataType>();
    }

    // used for bridge LDS shuffle
    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto GetSmemKPack_Y()
    {
        // TODO: this should match mfma layout
        return 16 / sizeof(typename Problem::YDataType);
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr ck_tile::index_t GetSmemSize_A()
    {
        constexpr auto a_sld_desc = MakeLdsLoadDesc_A<Problem>();
        constexpr auto a_sst_desc = MakeLdsStoreDesc_A<Problem>();
        static_assert(a_sld_desc.get_element_space_size() == a_sst_desc.get_element_space_size());
        return a_sld_desc.get_element_space_size();
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr ck_tile::index_t GetSmemSize_G()
    {
        constexpr auto g_sld_desc = MakeLdsLoadDesc_G<Problem>();
        constexpr auto g_sst_desc = MakeLdsStoreDesc_G<Problem>();
        static_assert(g_sld_desc.get_element_space_size() == g_sst_desc.get_element_space_size());
        return g_sld_desc.get_element_space_size();
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr ck_tile::index_t GetSmemSize_Bridge()
    {
        constexpr auto bridge_sld_desc = MakeBridgeLdsLoadDesc<Problem>();
        constexpr auto bridge_sst_desc = MakeBridgeLdsStoreDesc<Problem>();
        static_assert(bridge_sld_desc.get_element_space_size() ==
                      bridge_sst_desc.get_element_space_size());
        return bridge_sld_desc.get_element_space_size();
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr ck_tile::index_t GetSmemSize_D()
    {
        constexpr auto d_sld_desc = MakeLdsStoreDesc_D<Problem>();
        constexpr auto d_sst_desc = MakeLdsStoreDesc_D<Problem>();

        static_assert(d_sld_desc.get_element_space_size() == d_sst_desc.get_element_space_size());
        return d_sld_desc.get_element_space_size();
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr ck_tile::index_t GetSmemSize()
    {
        constexpr index_t a_lds      = GetSmemSize_A<Problem>();
        constexpr index_t bridge_lds = GetSmemSize_Bridge<Problem>();
        constexpr index_t d_lds      = Problem::IsSwizzled ? (GetSmemSize_D<Problem>() * 2)     // in <GetSmemSize_D::MakeLdsStoreDesc_D>, the block_k has been divided by 2
                                                    : GetSmemSize_D<Problem>();
        return max(max(a_lds, bridge_lds), d_lds);
    }

    template <index_t MPerBlock, index_t KPerBlock, index_t NumWarps, index_t Alignment>
    CK_TILE_HOST_DEVICE static constexpr auto MakeGlobalTileDistribution_SimpleMxK()
    {
        constexpr index_t K_vec = Alignment;
        constexpr index_t K_rem = KPerBlock / K_vec;

        if constexpr(get_warp_size() < K_rem)
        {
            static_assert(K_rem % get_warp_size() == 0);
            constexpr index_t K_lan = get_warp_size(); // lane within same wave is along gemm-k
            constexpr index_t K_wav = K_rem / get_warp_size();
            static_assert(K_wav <= NumWarps, "not not support thread has repeat along K yet");
            constexpr index_t M_wav = NumWarps / K_wav;
            static_assert(MPerBlock % M_wav == 0, "this tile size is too small please check");
            constexpr index_t M_rep = MPerBlock / M_wav;

            return make_static_tile_distribution(
                tile_distribution_encoding<
                    sequence<1>,
                    tuple<sequence<M_rep, M_wav>, sequence<K_wav, K_lan, K_vec>>,
                    tuple<sequence<1, 2>, sequence<2>>,
                    tuple<sequence<1, 0>, sequence<1>>,
                    sequence<1, 2>,
                    sequence<0, 2>>{});
        }
        else
        {
            constexpr index_t K_lan = K_rem;
            constexpr index_t M_lan = get_warp_size() / K_lan;
            constexpr index_t M_wav = NumWarps;
            static_assert(MPerBlock % (M_lan * M_wav) == 0,
                          "this tile size is too small please check");
            constexpr index_t M_rep = MPerBlock / (M_lan * M_wav);
            return make_static_tile_distribution(
                tile_distribution_encoding<
                    sequence<1>,
                    tuple<sequence<M_rep, M_wav, M_lan>, sequence<K_lan, K_vec>>,
                    tuple<sequence<1>, sequence<1, 2>>,
                    tuple<sequence<1>, sequence<2, 0>>,
                    sequence<1, 2>,
                    sequence<0, 1>>{});
        }
    }

    // optimized version for async, not same as simple MXK dist(pay attention!!)
    template <index_t MPerBlock, index_t KPerBlock, index_t NumWarps, index_t Alignment>
    CK_TILE_HOST_DEVICE static constexpr auto MakeGlobalTileDistribution_SimpleMxK_Async()
    {
        constexpr index_t K_vec = Alignment;
        constexpr index_t K_rem = KPerBlock / K_vec;

        if constexpr(get_warp_size() <= K_rem)
        {
            static_assert(false);
        }
        else
        {
            constexpr index_t K_lan = K_rem;
            constexpr index_t M_lan = get_warp_size() / K_lan;
            constexpr index_t M_wav = NumWarps;
            static_assert(MPerBlock % (M_lan * M_wav) == 0,
                          "this tile size is too small please check");
            constexpr index_t M_rep = MPerBlock / (M_lan * M_wav);
            // NOTE: swapped for LDS load bank conflict free
            return make_static_tile_distribution(
                tile_distribution_encoding<
                    sequence<1>,
                    tuple<sequence<M_rep, M_wav, M_lan>, sequence<K_lan, K_vec>>,
                    tuple<sequence<1>, sequence<1, 2>>,
                    tuple<sequence<1>, sequence<2, 0>>,
                    sequence<1, 2>,
                    sequence<0, 1>>{});
        }
    }

    template <index_t WarpPerBlock_N_,
              index_t WarpPerBlock_K_,
              index_t Repeat_N_,
              index_t Repeat_K_,
              index_t WarpSize_,
              index_t Alignment_>
    CK_TILE_HOST_DEVICE static constexpr auto MakeGlobalTileDistribution_Nr_Kr_W()
    {
        return make_static_tile_distribution(
            tile_distribution_encoding<sequence<1>,
                                       tuple<sequence<Repeat_N_, WarpPerBlock_N_>,
                                             sequence<Repeat_K_, WarpPerBlock_K_>,
                                             sequence<WarpSize_, Alignment_>>,
                                       tuple<sequence<1, 2>, sequence<3>>,
                                       tuple<sequence<1, 1>, sequence<0>>,
                                       sequence<1, 2, 3>,
                                       sequence<0, 0, 1>>{});
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeGlobalTileDistribution_A()
    {
        constexpr index_t Block_M_   = Problem::BlockShape::Block_M0;
        constexpr index_t Block_K_   = Problem::BlockShape::Block_K0;
        constexpr index_t NumWarps_  = Problem::BlockShape::NumWarps;
        constexpr index_t Alignment_ = GetAlignment_A<Problem>();
        return MakeGlobalTileDistribution_SimpleMxK_Async<Block_M_,
                                                          Block_K_,
                                                          NumWarps_,
                                                          Alignment_>();
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeGlobalTileDistribution_G()
    {
        // constexpr auto PermuteEnum = Problem::Traits::PermuteEnum;
        // constexpr index_t hidden_radio_0 = Problem::Traits::IsGateOnly ? 1 : 2;

        constexpr index_t Block_N  = Problem::BlockShape::Block_N0;
        constexpr index_t Block_K  = Problem::BlockShape::Block_K0;
        constexpr index_t NumWarps = Problem::BlockShape::NumWarps;

        constexpr index_t KVecotrLength = GetAlignment_G<Problem>();
        constexpr index_t KLane         = Block_K / KVecotrLength;

        constexpr index_t NLane       = get_warp_size() / KLane;
        constexpr index_t NInterleave = Problem::Gemm0NInterleave;
        static_assert(NInterleave * NLane * NumWarps == Block_N,
                      "GEMM0 tiling method in N direction is wrong!");

        return make_static_tile_distribution(
            tile_distribution_encoding<
                sequence<1>,
                tuple<sequence<number<NumWarps>{}, number<NLane>{}, number<NInterleave>{}>,
                      sequence<number<KLane>{}, number<KVecotrLength>{}>>,
                tuple<sequence<1>, sequence<2, 1>>, // thread layout
                tuple<sequence<0>, sequence<0, 1>>, // 256
                sequence<1, 2>,                     // ys length
                sequence<2, 1>>{});
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeGlobalTileDistribution_D()
    {
        // Note: This version is not only for VGPR but also for async LDS. Here just continuous read
        // from global.
        // constexpr auto PermuteEnum = Problem::Traits::PermuteEnum;
        // using S_                   = typename Problem::BlockShape;
        constexpr index_t Block_N_   = Problem::BlockShape::Block_N1;
        constexpr index_t Block_K_ = Problem::IsSwizzled ? (Problem::BlockShape::Block_K1 / 2)   // divide 2 will make the lds col = 64, that leads to 128 Bytes.
                                                    : Problem::BlockShape::Block_K1;
        constexpr index_t NumWarps_  = Problem::BlockShape::NumWarps;
        constexpr index_t Alignment_ = GetAlignment_D<Problem>();

        constexpr index_t K_vec = Alignment_;
        constexpr index_t K_rem = Block_K_ / K_vec;
        constexpr index_t K_lan = K_rem;
        constexpr index_t N_lan = get_warp_size() / K_lan;
        constexpr index_t N_wav = NumWarps_;
        static_assert(Block_N_ % (N_lan * N_wav) == 0, "this tile size is too small please check");
        constexpr index_t N_rep = Block_N_ / (N_lan * N_wav);
        // NOTE: swapped for LDS load bank conflict free
        return make_static_tile_distribution(
            tile_distribution_encoding<sequence<>,
                                       tuple<sequence<N_rep, N_wav, N_lan>, sequence<K_lan, K_vec>>,
                                       tuple<sequence<1>, sequence<1, 2>>,
                                       tuple<sequence<1>, sequence<2, 0>>,
                                       sequence<1, 2>,
                                       sequence<0, 1>>{});
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeGlobalTileDistribution_O()
    {
        using S_ = remove_cvref_t<typename Problem::BlockShape>;
        using WarpGemm =
            typename remove_cvref_t<decltype(GetWarpGemm1<Problem>())>::WarpGemmAttribute;

        // number<1> -> M0PerLane
        static_assert(WarpGemm::MInterleave == 1, "MInterleave not support interleave");
        static_assert(S_::Repeat_N1 == 1 && WarpGemm::NRepeat == 1 && WarpGemm::NInterleave == 1,
                      "Not Support multi mmac issues in N Direction");
        constexpr auto c_output_dstr_encoding =
            tile_distribution_encoding<sequence<>,
                                       tuple<sequence<S_::Repeat_M1,
                                                      S_::WarpPerBlock_M1,
                                                      number<1>{},
                                                      WarpGemm::MInterleave,
                                                      number<1>{},
                                                      WarpGemm::Impl::kCMLane,
                                                      WarpGemm::Impl::kCM1PerLane>,
                                             sequence<S_::Repeat_N1,
                                                      S_::WarpPerBlock_N1,
                                                      WarpGemm::NRepeat,
                                                      WarpGemm::NInterleave,
                                                      WarpGemm::Impl::kCNLane,
                                                      WarpGemm::Impl::kCNPerLane>>,
                                       tuple<sequence<1, 2>, sequence<1, 2>>,
                                       tuple<sequence<1, 1>, sequence<5, 4>>,
                                       sequence<1, 2, 1, 2, 1, 2, 2, 1, 1>,
                                       sequence<0, 0, 2, 2, 3, 3, 5, 4, 6>>{};

        constexpr auto c_block_dstr = make_static_tile_distribution(c_output_dstr_encoding);
        return c_block_dstr;
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeLdsStoreDesc_A()
    {
        // A async->LDS
        constexpr index_t Block_M = Problem::BlockShape::Block_M0;
        constexpr index_t Block_K = Problem::BlockShape::Block_K0;
        // constexpr index_t BlockSize = Problem::BlockShape::BlockSize;
        constexpr index_t warpSize = ck_tile::get_warp_size();
        constexpr index_t NumWarps = Problem::BlockShape::NumWarps;

        // constexpr index_t KPack   = GetSmemKPack_A<Problem>(); // LDS
        constexpr index_t KVector =
            GetAlignment_A<Problem>(); // choose 1/2/4 dword(must use 4 warps now)
        // TODO: support pad mode
        // constexpr index_t KPad    = KPack;                     // pad between warps

        static_assert(Block_K % KVector == 0);
        constexpr index_t LanesPerK = Block_K / KVector; // how many thread loading K 32/4 = 8
        if constexpr(LanesPerK >= warpSize)
        {
            static_assert(false, "Not Support block K bigger than warpsize x vector");
        }
        else
        {
            // lanes within a wave load different M but same K
            static_assert(warpSize % LanesPerK == 0);
            constexpr index_t MLane     = warpSize / LanesPerK;         // along m  8
            constexpr index_t NumIssues = Block_M / (MLane * NumWarps); // dwordx2 1Issue

            constexpr auto a_lds_block_desc = ck_tile::make_naive_tensor_descriptor_packed(
                make_tuple(number<Block_M>{}, number<Block_K>{}), number<KVector>{});

            constexpr auto a_lds_block_desc_unmerged = transform_tensor_descriptor(
                a_lds_block_desc,
                make_tuple(
                    make_unmerge_transform(
                        make_tuple(number<NumIssues>{}, number<NumWarps>{}, number<MLane>{})),
                    make_unmerge_transform(make_tuple(number<LanesPerK>{}, number<KVector>{}))),
                make_tuple(sequence<0>{}, sequence<1>{}),
                make_tuple(sequence<0, 1, 2>{}, sequence<3, 4>{}));

            return transform_tensor_descriptor(
                a_lds_block_desc_unmerged,
                make_tuple(make_pass_through_transform(number<NumIssues>{}),
                           make_pass_through_transform(number<NumWarps>{}),
                           make_merge_transform(make_tuple(
                               number<MLane>{}, number<LanesPerK>{}, number<KVector>{}))),
                make_tuple(sequence<0>{}, sequence<1>{}, sequence<2, 3, 4>{}),
                make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}));
        }
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeLdsLoadDesc_A()
    {
        constexpr index_t Block_M  = Problem::BlockShape::Block_M0;
        constexpr index_t Block_K  = Problem::BlockShape::Block_K0;
        constexpr index_t warpSize = ck_tile::get_warp_size();

        constexpr index_t KVector = Problem::ASmemLoadVectorLength;
        // constexpr index_t KPack   = GetSmemKPack_A<Problem>(); // LDS
        // constexpr index_t KVector = GetAlignment_A<Problem>(); // async copy 1 dword
        // constexpr index_t KPad    = KPack;                     // pad between warps

        static_assert(Block_K % KVector == 0);
        constexpr index_t LanesPerK = Block_K / KVector; // how many thread loading K
        if constexpr(LanesPerK >= warpSize)
        {
            static_assert(false, "not supported yet!");
        }
        else
        {
            // lanes within a wave load different M but same K
            // Note: Every wave will use same Block M
            static_assert(warpSize % LanesPerK == 0);
            constexpr index_t LaneGroups = warpSize / LanesPerK; // along m
            constexpr index_t NumIssues =
                Block_M / (LaneGroups * Problem::BlockShape::WarpPerBlock_M0);

            constexpr auto lds_block_desc_0 = make_naive_tensor_descriptor(
                make_tuple(number<NumIssues>{},                        // m0
                           number<LanesPerK>{},                        // k0
                           number<LaneGroups>{},                       // m1
                           number<KVector>{}),                         // k1
                make_tuple(number<KVector * LaneGroups * LanesPerK>{}, // m1
                           number<KVector>{},                          // m2
                           number<KVector * LanesPerK>{},              // k0
                           number<1>{}),                               // k1
                number<KVector>{},                                     // lds load vector
                number<1>{});

            constexpr auto lds_desc_m_k = transform_tensor_descriptor(
                lds_block_desc_0,
                make_tuple(
                    make_merge_transform(make_tuple(number<NumIssues>{}, number<LaneGroups>{})),
                    make_merge_transform(make_tuple(number<LanesPerK>{}, number<KVector>{}))),
                make_tuple(sequence<0, 2>{}, sequence<1, 3>{}),
                make_tuple(sequence<0>{}, sequence<1>{}));

            return lds_desc_m_k;
        }
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeLdsStoreDesc_G()
    {
        // gate/up vgpr->lds
        constexpr index_t Block_N  = Problem::BlockShape::Block_N0;
        constexpr index_t Block_K  = Problem::BlockShape::Block_K0;
        constexpr index_t NumWarps = Problem::BlockShape::NumWarps;

        constexpr index_t KVecotrLength = Problem::GSmemStoreVectorLength;
        constexpr index_t KLane         = Block_K / KVecotrLength;

        constexpr index_t NLane       = get_warp_size() / KLane;
        constexpr index_t NInterleave = Problem::Gemm0NInterleave;
        static_assert(NInterleave * NLane * NumWarps == Block_N,
                      "GEMM0 tiling method in N direction is wrong!");

        constexpr auto lds_block_desc_base = ck_tile::make_naive_tensor_descriptor(
            make_tuple(NumWarps, NInterleave, NLane, KLane, KVecotrLength),
            make_tuple(NLane * NInterleave * KLane * KVecotrLength,
                       KLane * KVecotrLength,
                       NInterleave * KLane * KVecotrLength, // 4 interleave x 4
                       KVecotrLength,
                       1),
            number<KVecotrLength>{},
            number<1>{});

        return ck_tile::transform_tensor_descriptor(
            lds_block_desc_base,
            make_tuple(make_merge_transform(make_tuple(NumWarps, NInterleave, NLane)),
                       make_merge_transform(make_tuple(KLane, KVecotrLength))),
            make_tuple(sequence<0, 1, 2>{}, sequence<3, 4>{}),
            make_tuple(sequence<0>{}, sequence<1>{}));
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeLdsLoadDesc_G()
    {
        // gate/up lds->vgpr
        constexpr index_t Block_N  = Problem::BlockShape::Block_N0;
        constexpr index_t Block_K  = Problem::BlockShape::Block_K0;
        constexpr index_t NumWarps = Problem::BlockShape::NumWarps;

        constexpr index_t KVecotrLength = Problem::GSmemStoreVectorLength;
        constexpr index_t KLane         = Block_K / KVecotrLength;

        constexpr index_t NLane       = get_warp_size() / KLane;
        constexpr index_t NInterleave = Problem::Gemm0NInterleave;
        static_assert(NInterleave * NLane * NumWarps == Block_N,
                      "GEMM0 tiling method in N direction is wrong!");

        // Notice:: stride in NInterleave dimension is different from store cause we have already
        // read interleave elements from global, and write them into LDS.
        constexpr auto lds_block_desc_base =
            ck_tile::make_naive_tensor_descriptor(make_tuple( // length
                                                      NumWarps,
                                                      NInterleave,
                                                      NLane,
                                                      KLane,
                                                      KVecotrLength),
                                                  make_tuple( // stride
                                                      NLane * NInterleave * KLane * KVecotrLength,
                                                      NLane * KLane * KVecotrLength,
                                                      KLane * KVecotrLength,
                                                      KVecotrLength,
                                                      1),
                                                  number<KVecotrLength>{},
                                                  number<1>{});

        return ck_tile::transform_tensor_descriptor(
            lds_block_desc_base,
            make_tuple(make_merge_transform(make_tuple(NumWarps, NInterleave, NLane)),
                       make_merge_transform(make_tuple(KLane, KVecotrLength))),
            make_tuple(sequence<0, 1, 2>{}, sequence<3, 4>{}),
            make_tuple(sequence<0>{}, sequence<1>{}));
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeBridgeTileDistribution()
    {
        using WarpGemm  = remove_cvref_t<decltype(GetWarpGemm0<Problem>())>;
        constexpr index_t kCN0PerLane = WarpGemm::WarpGemmAttribute::Impl::kCN0PerLane;

        constexpr index_t NVector     = Problem::BridgeSmemStoreVectorLength;
        constexpr index_t MLane       = 16; // ugly, 16 fixed for mmac
        constexpr index_t NLane       = get_warp_size() / MLane;
        // constexpr index_t NInterleave = Problem::Gemm0NInterleave;
        constexpr index_t NWarps      = Problem::BlockShape::WarpPerBlock_N0;
        constexpr index_t MWarps      = Problem::BlockShape::WarpPerBlock_M0;
        static_assert(NVector * NLane * kCN0PerLane == Problem::BlockShape::Warp_N0,
                      "Gemm0 bridge setting is wrong !");
        constexpr index_t MRepeat = Problem::BlockShape::Warp_M0 / MLane;

        constexpr auto bridge_tile_dstr_enc = tile_distribution_encoding<
            sequence<>,
            tuple<sequence<MRepeat, MWarps, MLane>, sequence<NWarps, kCN0PerLane, NLane, NVector>>,
            tuple<sequence<1, 2>, sequence<2, 1>>,
            tuple<sequence<1, 0>, sequence<2, 2>>,
            sequence<1, 2, 2>,
            sequence<0, 1, 3>>{};
        constexpr auto bridge_tile_dstr = make_static_tile_distribution(bridge_tile_dstr_enc);
        return bridge_tile_dstr;
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeBridgeLdsLoadDesc()
    {
        using WarpGemm  = remove_cvref_t<decltype(GetWarpGemm0<Problem>())>;
        constexpr index_t kCN0PerLane = WarpGemm::WarpGemmAttribute::Impl::kCN0PerLane;

        constexpr index_t NVector     = Problem::BridgeSmemStoreVectorLength;
        constexpr index_t MLane       = 16; // ugly, 16 fixed for mmac
        constexpr index_t NLane       = get_warp_size() / MLane;
        // constexpr index_t NInterleave = Problem::Gemm0NInterleave;
        constexpr index_t NWarps      = Problem::BlockShape::WarpPerBlock_N0;
        constexpr index_t MWarps      = Problem::BlockShape::WarpPerBlock_M0;
        static_assert(NLane == 4 && kCN0PerLane == 4 && (NVector==4 || NVector==2));
        static_assert(NVector * NLane * kCN0PerLane == Problem::BlockShape::Warp_N0,
                      "Gemm0 bridge setting is wrong !");
        constexpr index_t MRepeat = Problem::BlockShape::Warp_M0 / MLane;

        // constexpr index_t KVector = GetSmemKPack_Y<Problem>(); // async copy 1 dword
        // constexpr index_t KPad    = 0;                         // pad between warps

        constexpr auto desc = make_naive_tensor_descriptor(
            make_tuple(number<MWarps>{},
                       number<NWarps>{},
                       number<MRepeat>{},
                       number<kCN0PerLane>{},
                       number<NLane>{},
                       number<MLane>{},
                       number<NVector>{}),
            make_tuple(number<NWarps * MRepeat * kCN0PerLane * NLane * MLane * NVector>{},
                       number<MRepeat * kCN0PerLane * NLane * MLane * NVector>{},
                       number<kCN0PerLane * NLane * MLane * NVector>{},
                       number<NLane * MLane * NVector>{},
                       number<MLane * NVector>{},
                       number<NVector>{},
                       number<1>{}),
            number<NVector>{},
            number<1>{});
        constexpr auto load_trans_desc = transform_tensor_descriptor(
            desc,
            make_tuple(make_pass_through_transform(MRepeat),
                       make_pass_through_transform(MWarps),
                       make_merge_transform(make_tuple(NWarps, kCN0PerLane)),
                       make_pass_through_transform(NLane),
                       make_pass_through_transform(MLane),
                       make_pass_through_transform(NVector)),
            make_tuple(sequence<2>{},
                       sequence<0>{},
                       sequence<1, 3>{},
                       sequence<4>{},
                       sequence<5>{},
                       sequence<6>{}),
            make_tuple(sequence<0>{},
                       sequence<1>{},
                       sequence<2>{},
                       sequence<3>{},
                       sequence<4>{},
                       sequence<5>{}));

        constexpr auto load_trans_desc2 = transform_tensor_descriptor(
            load_trans_desc,
            make_tuple(make_merge_transform(make_tuple(MRepeat, MWarps)),
                       make_pass_through_transform(NWarps * kCN0PerLane),
                       make_pass_through_transform(NLane),
                       make_pass_through_transform(MLane),
                       make_pass_through_transform(NVector)),
            make_tuple(
                sequence<0, 1>{}, sequence<2>{}, sequence<3>{}, sequence<4>{}, sequence<5>{}),
            make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}, sequence<4>{}));
        return transform_tensor_descriptor(
            load_trans_desc2,
            make_tuple(make_merge_transform(make_tuple(MWarps * MRepeat, MLane)),
                       make_merge_transform(make_tuple(NWarps * kCN0PerLane, NLane, NVector))),
            make_tuple(sequence<0, 3>{}, sequence<1, 2, 4>{}),
            make_tuple(sequence<0>{}, sequence<1>{}));
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeBridgeLdsStoreDesc()
    {
        // Note: layout depends on BridgeTileDistribution
        // constexpr index_t Block_M0 = Problem::BlockShape::Block_M0;
        // constexpr index_t Block_N0 = Problem::BlockShape::Block_N0;
        using WarpGemm  = remove_cvref_t<decltype(GetWarpGemm0<Problem>())>;
        constexpr index_t kCN0PerLane = WarpGemm::WarpGemmAttribute::Impl::kCN0PerLane;

        constexpr index_t NVector     = Problem::BridgeSmemStoreVectorLength;
        constexpr index_t MLane       = 16; // ugly, 16 fixed for mmac
        constexpr index_t NLane       = get_warp_size() / MLane;
        // constexpr index_t NInterleave = Problem::Gemm0NInterleave;
        constexpr index_t NWarps      = Problem::BlockShape::WarpPerBlock_N0;
        constexpr index_t MWarps      = Problem::BlockShape::WarpPerBlock_M0;
        static_assert(NLane == 4 && kCN0PerLane == 4 && (NVector==4 || NVector==2));
        static_assert(NVector * NLane * kCN0PerLane == Problem::BlockShape::Warp_N0,
                      "Gemm0 bridge setting is wrong !");
        constexpr index_t MRepeat = Problem::BlockShape::Warp_M0 / MLane;

        // constexpr index_t KVector = GetSmemKPack_Y<Problem>(); // async copy 1 dword
        // constexpr index_t KPad    = 0;                         // pad between warps

        constexpr auto desc = make_naive_tensor_descriptor(
            make_tuple(number<MWarps>{},
                       number<NWarps>{},
                       number<MRepeat>{},
                       number<kCN0PerLane>{},
                       number<NLane>{},
                       number<MLane>{},
                       number<NVector>{}),
            make_tuple(number<NWarps * MRepeat * kCN0PerLane * NLane * MLane * NVector>{},
                       number<MRepeat * kCN0PerLane * NLane * MLane * NVector>{},
                       number<kCN0PerLane * NLane * MLane * NVector>{},
                       number<NLane * MLane * NVector>{},
                       number<MLane * NVector>{},
                       number<NVector>{},
                       number<1>{}),
            number<NVector>{},
            number<1>{});
        return transform_tensor_descriptor(
            desc,
            make_tuple(make_merge_transform(make_tuple(MWarps, MRepeat, MLane)),
                       make_merge_transform(make_tuple(NWarps, kCN0PerLane, NLane, NVector))),
            make_tuple(sequence<0, 2, 5>{}, sequence<1, 3, 4, 6>{}),
            make_tuple(sequence<0>{}, sequence<1>{}));
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeLdsStoreDesc_D()
    {
        // D async->LDS(also for vgpr)
        constexpr index_t Block_N = Problem::BlockShape::Block_N1;
        constexpr index_t Block_K = Problem::IsSwizzled ? (Problem::BlockShape::Block_K1 / 2)   // divide 2 will make the lds col = 64, that leads to 128 Bytes.
                                                    : Problem::BlockShape::Block_K1;
        // constexpr index_t BlockSize = Problem::BlockShape::BlockSize;
        constexpr index_t warpSize = ck_tile::get_warp_size();
        constexpr index_t NumWarps = Problem::BlockShape::NumWarps;

        // TODO: use kpack as kpad for bank conflict free.
        // constexpr index_t KPack   = GetSmemKPack_A<Problem>(); // LDS
        constexpr index_t KVector =
            GetAlignment_D<Problem>(); // choose 1/2/4 dword(must use 4 warps now)
        // constexpr index_t KPad    = KPack;                     // pad between warps

        static_assert(Block_K % KVector == 0);
        constexpr index_t KLane = Block_K / KVector; // how many thread loading K 256/8 32
        if constexpr(KLane >= warpSize)
        {
            static_assert(false, "Not Support block K bigger than warpsize x vector");
        }
        else
        {
            // lanes within a wave load different M but same K
            static_assert(warpSize % KLane == 0);
            constexpr index_t NLane     = warpSize / KLane;             // along m  2
            constexpr index_t NumIssues = Block_N / (NLane * NumWarps); // dwordx2 1Issue

            constexpr auto d_lds_block_desc = ck_tile::make_naive_tensor_descriptor_packed(
                make_tuple(number<Block_N>{}, number<Block_K>{}), number<KVector>{});

            constexpr auto d_lds_block_desc_unmerged = transform_tensor_descriptor(
                d_lds_block_desc,
                make_tuple(make_unmerge_transform(make_tuple(
                               number<NumIssues>{}, number<NumWarps>{}, number<NLane>{})),
                           make_unmerge_transform(make_tuple(number<KLane>{}, number<KVector>{}))),
                make_tuple(sequence<0>{}, sequence<1>{}),
                make_tuple(sequence<0, 1, 2>{}, sequence<3, 4>{}));

            return transform_tensor_descriptor(
                d_lds_block_desc_unmerged,
                make_tuple(make_merge_transform(make_tuple(
                               number<NumIssues>{}, number<NumWarps>{}, number<NLane>{})),
                           make_merge_transform(make_tuple(number<KLane>{}, number<KVector>{}))),
                make_tuple(sequence<0, 1, 2>{}, sequence<3, 4>{}),
                make_tuple(sequence<0>{}, sequence<1>{}));
        }
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeLdsLoadDesc_D()
    {
        // Note: Desc here is just for basic LDS descriptor, all vgpr distribution will put into
        // dTileDistribution
        constexpr index_t Block_N = Problem::BlockShape::Block_N1;
        constexpr index_t Block_K = Problem::IsSwizzled ? (Problem::BlockShape::Block_K1 / 2)   // divide 2 will make the lds col = 64, that leads to 128 Bytes.
                                                    : Problem::BlockShape::Block_K1;
        constexpr index_t KVector = Problem::DSmemLoadVectorLength;

        return make_naive_tensor_descriptor_packed(make_tuple(number<Block_N>{}, number<Block_K>{}),
                                                   number<KVector>{});
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto GetWarpGemm0()
    {
        using S_ = typename Problem::BlockShape;
        // A is vgpr, B is agpr. But since we transposed, so also need swap this
        // TODO: this is ugly
        if constexpr(std::is_same_v<typename Problem::ADataType, ck_tile::half_t> &&
                     std::is_same_v<typename Problem::GDataType, ck_tile::half_t> &&
                     S_::Warp_M0 == 32 && S_::Warp_N0 == 64 && S_::Warp_K0 == 32)
        {
            return WarpGemmMmacF16F16F32_WT32x64x32_MR2NR1MI1NI4{};
        }
        else if constexpr(std::is_same_v<typename Problem::ADataType, ck_tile::half_t> &&
                          std::is_same_v<typename Problem::GDataType, ck_tile::half_t> &&
                          S_::Warp_M0 == 16 && S_::Warp_N0 == 32 && S_::Warp_K0 == 128)
        {
            return WarpGemmMmacF16F16F32_WT16x32x128_MR1NR1MI1NI2{};
        }
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto GetWarpGemm1()
    {
        using S_ = typename Problem::BlockShape;
        // static_assert( S_::Warp_M1 == 32 && S_::Warp_N1 == 16 && S_::Warp_K1 == 256);
        if constexpr(std::is_same_v<typename Problem::ADataType, ck_tile::half_t> &&
                     std::is_same_v<typename Problem::GDataType, ck_tile::half_t> &&
                     S_::Warp_M1 == 32 && S_::Warp_N1 == 16 && S_::Warp_K1 == 256)
        {
            return WarpGemmMmacF16F16F32_WT32x16x256_MR2NR1MI1NI1_TRANSC_LEGACY{};
        }
        else if constexpr(std::is_same_v<typename Problem::ADataType, ck_tile::half_t> &&
                          std::is_same_v<typename Problem::GDataType, ck_tile::half_t> &&
                          S_::Warp_M1 == 16 && S_::Warp_N1 == 16 && S_::Warp_K1 == 128)
        {
            if constexpr(Problem::IsSwizzled) {
                return WarpGemmMmacF16F16F32_WT16x16x64_MR1NR1MI1NI1_TRANSC_LEGACY{};
            } else {
                return WarpGemmMmacF16F16F32_WT16x16x128_MR1NR1MI1NI1_TRANSC_LEGACY{};
            }
        }

    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeCBlockTile_Gemm0()
    {
        using S_        = remove_cvref_t<typename Problem::BlockShape>;
        using WarpGemm  = remove_cvref_t<decltype(GetWarpGemm0<Problem>())>;
        using CDataType = typename WarpGemm::CDataType;

        constexpr auto c_block_outer_dstr_encoding =
            tile_distribution_encoding<sequence<>,
                                       tuple<sequence<S_::Repeat_M0, S_::WarpPerBlock_M0>,
                                             sequence<S_::Repeat_N0, S_::WarpPerBlock_N0>>,
                                       tuple<sequence<1, 2>>,
                                       tuple<sequence<1, 1>>,
                                       sequence<1, 2>,
                                       sequence<0, 0>>{};

        constexpr auto c_block_dstr_encode = detail::make_embed_tile_distribution_encoding(
            c_block_outer_dstr_encoding, typename WarpGemm::CWarpDstrEncoding{});
        constexpr auto c_block_dstr = make_static_tile_distribution(c_block_dstr_encode);
        auto c_block_tensor         = make_static_distributed_tensor<CDataType>(c_block_dstr);
        return c_block_tensor;
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeCBlockTile_Gemm1()
    {
        using S_        = remove_cvref_t<typename Problem::BlockShape>;
        using WarpGemm  = remove_cvref_t<decltype(GetWarpGemm1<Problem>())>;
        using CDataType = typename WarpGemm::CDataType;

        constexpr auto c_block_outer_dstr_encoding =
            tile_distribution_encoding<sequence<>,
                                       tuple<sequence<S_::Repeat_M1, S_::WarpPerBlock_M1>,
                                             sequence<S_::Repeat_N1, S_::WarpPerBlock_N1>>,
                                       tuple<sequence<1, 2>>,
                                       tuple<sequence<1, 1>>,
                                       sequence<1, 2>,
                                       sequence<0, 0>>{};

        constexpr auto c_block_dstr_encode = detail::make_embed_tile_distribution_encoding(
            c_block_outer_dstr_encoding, typename WarpGemm::CWarpDstrEncoding{});
        constexpr auto c_block_dstr = make_static_tile_distribution(c_block_dstr_encode);
        auto c_block_tensor         = make_static_distributed_tensor<CDataType>(c_block_dstr);
        return c_block_tensor;
    }

    // this is used as A matrix for 2nd gemm
    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeYTileDistribution()
    {
        using S_       = remove_cvref_t<typename Problem::BlockShape>;
        using WarpGemm = remove_cvref_t<decltype(GetWarpGemm1<Problem>())>;

        // TODO: all waves a along different N, but same M
        // Notice replication dims here! all waves along N  can have same element space
        constexpr auto y_outer_dstr_enc =
            tile_distribution_encoding<sequence<S_::WarpPerBlock_M1>,
                                       tuple<sequence<S_::Repeat_M1>, sequence<S_::Repeat_K1>>,
                                       tuple<sequence<0>>,
                                       tuple<sequence<0>>,
                                       sequence<1, 2>,
                                       sequence<0, 0>>{};

        constexpr auto y_block_dstr_encode = detail::make_embed_tile_distribution_encoding(
            y_outer_dstr_enc, typename WarpGemm::AWarpDstrEncoding{});
        constexpr auto y_block_dstr = make_static_tile_distribution(y_block_dstr_encode);
        return y_block_dstr;
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeYBlockTile()
    {
        constexpr auto y_block_dstr = MakeYTileDistribution<Problem>();
        auto y_block_tensor =
            make_static_distributed_tensor<typename Problem::YDataType>(y_block_dstr);
        return y_block_tensor;
    }
};
} // namespace ck_tile
