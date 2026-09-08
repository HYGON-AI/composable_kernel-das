// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Info Technologies Ltd.

#pragma once

#include <functional>
#include <numeric>
#include <iterator>

#include "ck/tensor_description/cluster_descriptor.hpp"
#include "ck/utility/data_type.hpp"
#include "ck/tensor_operation/gpu/block/thread_group_tensor_slice_transfer_v4r1.hpp"
#include "ck/tensor_operation/gpu/thread/threadwise_tensor_slice_transfer.hpp"
#include "ck/tensor_operation/gpu/element/element_wise_operation.hpp"

namespace ck {

template <ck::index_t BlockSize,
          ck::index_t MinBlockPerCU,
          typename GridwiseBatchedTranspose,
          typename InGridDesc_N_H_W,
          typename OutGridDesc,
          typename InDataType,
          typename OutDataType,
          typename Block2TileMap>
__global__ void __launch_bounds__(BlockSize, MinBlockPerCU)
    kernel_batched_transpose(const InGridDesc_N_H_W in_grid_desc_n_h_w,
                             const OutGridDesc out_grid_desc_n_w_h,
                             const InDataType* p_in_global,
                             OutDataType* p_out_global,
                             index_t num_block_iterations,
                             const Block2TileMap block_2_tile_map)
{
    __shared__ char p_shared[GridwiseBatchedTranspose::GetSharedMemoryNumberOfByte()];

    GridwiseBatchedTranspose::Run(in_grid_desc_n_h_w,
                                  out_grid_desc_n_w_h,
                                  p_in_global,
                                  p_out_global,
                                  p_shared,
                                  num_block_iterations,
                                  block_2_tile_map);
}

template <typename InGridDesc_N_H_W,
          typename OutGridDesc_N_W_H,
          typename InDataType,
          typename OutDataType,
          index_t BlockSize,
          index_t NPerBlock,
          index_t HPerBlock,
          index_t WPerBlock,
          typename InBlockTransferThreadClusterLengths_N_H_W,
          typename OutBlockTransferThreadClusterLengths_N_W_H,
          index_t SrcScalarPerVector,
          index_t DstScalarPerVector,
          bool AddLdsExtraH>
struct GridwiseBatchedTranspose
{

    using ThisThreadBlock = ThisThreadBlock<BlockSize>;

    static constexpr auto I0 = Number<0>{};
    static constexpr auto I1 = Number<1>{};
    static constexpr auto I2 = Number<2>{};

    struct Block2TileMap
    {
        static constexpr index_t NumDim = InGridDesc_N_H_W::GetNumOfDimension();
        static_assert(3 == NumDim);

        Block2TileMap()                     = delete;
        Block2TileMap(const Block2TileMap&) = default;
        Block2TileMap(Block2TileMap&&)      = delete;

        ~Block2TileMap() = default;

        Block2TileMap& operator=(const Block2TileMap&) = delete;
        Block2TileMap& operator=(Block2TileMap&&)      = delete;

        explicit Block2TileMap(const InGridDesc_N_H_W& desc) : desc_(desc) {}

        __host__ constexpr index_t CalculateGridSize(const InGridDesc_N_H_W& desc,
                                                     const index_t num_block_iterations) const
        {
            const auto N0 = math::integer_divide_ceil(desc.GetLength(Number<NumDim - 3>{}),
                                                      NPerBlock * num_block_iterations);
            const auto H0 =
                math::integer_divide_ceil(desc.GetLength(Number<NumDim - 2>{}), HPerBlock);
            const auto W0 =
                math::integer_divide_ceil(desc.GetLength(Number<NumDim - 1>{}), WPerBlock);

            const index_t grid_size = N0 * H0 * W0;

            return grid_size;
        }

        template <typename TopIdx>
        __host__ __device__ constexpr auto CalculateBottomIndex(const TopIdx& idx_top,
                                                                index_t num_block_iterations) const
        {
            static_assert(TopIdx::Size() == 1);

            auto block_1d_id = idx_top[I0];

            const auto N0 = math::integer_divide_ceil(desc_.GetLength(Number<NumDim - 3>{}),
                                                      NPerBlock * num_block_iterations);
            const auto H0 =
                math::integer_divide_ceil(desc_.GetLength(Number<NumDim - 2>{}), HPerBlock);
            const auto W0 =
                math::integer_divide_ceil(desc_.GetLength(Number<NumDim - 1>{}), WPerBlock);

            return make_single_stage_tensor_adaptor(
                       make_tuple(make_merge_transform(make_tuple(N0, H0, W0))),
                       make_tuple(Sequence<0, 1, 2>{}),
                       make_tuple(Sequence<0>{}))
                .CalculateBottomIndex(make_multi_index(block_1d_id));
        }

        __host__ __device__ constexpr auto GetN0(const index_t num_block_iterations) const
        {
            return math::integer_divide_ceil(desc_.GetLength(Number<NumDim - 3>{}),
                                             NPerBlock * num_block_iterations);
        }

        private:
        const InGridDesc_N_H_W desc_;
    };

    using DefaultBlock2TileMap = Block2TileMap;

    __host__ __device__ static constexpr auto MakeDefaultBlock2TileMap(const InGridDesc_N_H_W& desc)
    {
        return DefaultBlock2TileMap{desc};
    }

    __host__ __device__ static constexpr auto GetBlockDesc_NPerBlock_WPerBlock_HPerBlock()
    {
        if constexpr(AddLdsExtraH)
        {
#if defined(__gfx946__)
            // gfx946 requires ds_read_b64 addresses to stay 8-byte aligned. A 4-byte row pad
            // makes alternating rows misaligned for FP16 tiles whose unpadded row is aligned.
            constexpr auto LdsPad = Number<8>{} / sizeof(OutDataType);
#else
            // pad 1 bank element
            constexpr auto LdsPad = Number<4>{} / sizeof(OutDataType);
#endif
            return make_naive_tensor_descriptor(
                make_tuple(Number<NPerBlock>{}, Number<WPerBlock>{}, Number<HPerBlock>{}),
                make_tuple(
                    Number<WPerBlock*(HPerBlock + LdsPad)>{}, Number<HPerBlock + LdsPad>{}, I1));
        }
        else
        {
            return make_naive_tensor_descriptor_packed(
                make_tuple(Number<NPerBlock>{}, Number<WPerBlock>{}, Number<HPerBlock>{}));
        }
    }

    __host__ __device__ static constexpr index_t GetSharedMemoryNumberOfByte()
    {
        constexpr auto block_desc_nperblock_wperblock_hperblock =
            GetBlockDesc_NPerBlock_WPerBlock_HPerBlock();

        return block_desc_nperblock_wperblock_hperblock.GetElementSpaceSize() * sizeof(OutDataType);
    }

    __host__ __device__ static constexpr bool
    CheckValidity(const InGridDesc_N_H_W& in_grid_desc_n_h_w,
                  const OutGridDesc_N_W_H& out_grid_desc_n_w_h)
    {
        constexpr index_t NumDim = InGridDesc_N_H_W::GetNumOfDimension();

        // check if we only swap last 2 dimensions
        bool valid = true;
        static_for<0, NumDim - 2, 1>{}([&](auto I) {
            if(valid && in_grid_desc_n_h_w.GetLength(I) != out_grid_desc_n_w_h.GetLength(I))
            {
                valid = false;
            }
        });

        return valid &&
               (in_grid_desc_n_h_w.GetLength(Number<NumDim - 1>{}) ==
                out_grid_desc_n_w_h.GetLength(Number<NumDim - 2>{})) &&
               (in_grid_desc_n_h_w.GetLength(Number<NumDim - 2>{}) ==
                out_grid_desc_n_w_h.GetLength(Number<NumDim - 1>{}));
    }

    template <typename Block2TileMap>
    __device__ static void Run(const InGridDesc_N_H_W in_grid_desc_n_h_w,
                               const OutGridDesc_N_W_H out_grid_desc_n_w_h,
                               const InDataType* p_in_global,
                               OutDataType* p_out_global,
                               void* __restrict__ p_shared,
                               index_t num_block_iterations,
                               const Block2TileMap& block_2_tile_map)
    {
        auto in_global_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            p_in_global, in_grid_desc_n_h_w.GetElementSpaceSize());

        auto out_global_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            p_out_global, out_grid_desc_n_w_h.GetElementSpaceSize());

        const auto block_work_idx = block_2_tile_map.CalculateBottomIndex(
            make_multi_index(get_block_1d_id()), num_block_iterations);

        const index_t n_block_data_idx_on_grid =
            __builtin_amdgcn_readfirstlane(block_work_idx[I0] * NPerBlock);

        const index_t h_block_data_idx_on_grid =
            __builtin_amdgcn_readfirstlane(block_work_idx[I1] * HPerBlock);

        const index_t w_block_data_idx_on_grid =
            __builtin_amdgcn_readfirstlane(block_work_idx[I2] * WPerBlock);

        const index_t block_n0_step = __builtin_amdgcn_readfirstlane(
            block_2_tile_map.GetN0(num_block_iterations) * NPerBlock);

        constexpr auto block_desc_nperblock_wperblock_hperblock =
            GetBlockDesc_NPerBlock_WPerBlock_HPerBlock();

        constexpr auto block_desc_nperblock_hperblock_wperblock =
            transform_tensor_descriptor(block_desc_nperblock_wperblock_hperblock,
                                        make_tuple(make_pass_through_transform(NPerBlock),
                                                   make_pass_through_transform(WPerBlock),
                                                   make_pass_through_transform(HPerBlock)),
                                        make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}),
                                        make_tuple(Sequence<0>{}, Sequence<2>{}, Sequence<1>{}));

        auto in_block_buf = make_dynamic_buffer<AddressSpaceEnum::Lds>(
            static_cast<OutDataType*>(p_shared),
            block_desc_nperblock_hperblock_wperblock.GetElementSpaceSize());

        using ck::tensor_operation::element_wise::PassThrough;

        auto in_global_load = ThreadGroupTensorSliceTransfer_v4r1<
            ThisThreadBlock,
            PassThrough,
            PassThrough,
            InMemoryDataOperationEnum::Set,
            Sequence<NPerBlock, HPerBlock, WPerBlock>, // block slice
            InBlockTransferThreadClusterLengths_N_H_W,
            Sequence<0, 1, 2>, // arrange order
            InDataType,
            OutDataType,
            decltype(in_grid_desc_n_h_w),
            decltype(block_desc_nperblock_hperblock_wperblock),
            Sequence<0, 1, 2>, // src access order
            Sequence<0, 2, 1>, // dst access order
            2,                 // src vector dim
            1,                 // dst vector dim
            SrcScalarPerVector,
            1,
            1,
            1,
            true,
            true>(in_grid_desc_n_h_w,
                  make_multi_index(
                      n_block_data_idx_on_grid, h_block_data_idx_on_grid, w_block_data_idx_on_grid),
                  PassThrough{},
                  block_desc_nperblock_hperblock_wperblock,
                  make_multi_index(0, 0, 0),
                  PassThrough{});

        auto out_global_store = ThreadGroupTensorSliceTransfer_v4r1<
            ThisThreadBlock,
            PassThrough,
            PassThrough,
            InMemoryDataOperationEnum::Set,
            Sequence<NPerBlock, WPerBlock, HPerBlock>, // block slice
            OutBlockTransferThreadClusterLengths_N_W_H,
            Sequence<0, 1, 2>, // arrange order
            OutDataType,
            OutDataType,
            decltype(block_desc_nperblock_wperblock_hperblock),
            decltype(out_grid_desc_n_w_h),
            Sequence<0, 1, 2>, // src access order
            Sequence<0, 1, 2>, // dst access order
            2,                 // src vector dim
            2,                 // dst vector dim
            DstScalarPerVector,
            DstScalarPerVector,
            1,
            1,
            true,
            true>(block_desc_nperblock_wperblock_hperblock,
                  make_multi_index(0, 0, 0),
                  PassThrough{},
                  out_grid_desc_n_w_h,
                  make_multi_index(
                      n_block_data_idx_on_grid, w_block_data_idx_on_grid, h_block_data_idx_on_grid),
                  PassThrough{});

        auto block_copy_step = make_multi_index(block_n0_step, 0, 0);

        for(index_t i = 0; i < num_block_iterations; ++i)
        {
            block_sync_lds();

            in_global_load.Run(in_grid_desc_n_h_w,
                               in_global_buf,
                               block_desc_nperblock_hperblock_wperblock,
                               in_block_buf,
                               I0);

            block_sync_lds();

            out_global_store.Run(block_desc_nperblock_wperblock_hperblock,
                                 in_block_buf,
                                 out_grid_desc_n_w_h,
                                 out_global_buf,
                                 I0);

            in_global_load.MoveSrcSliceWindow(in_grid_desc_n_h_w, block_copy_step);

            out_global_store.MoveDstSliceWindow(out_grid_desc_n_w_h, block_copy_step);
        }
    }
};
} // namespace ck
