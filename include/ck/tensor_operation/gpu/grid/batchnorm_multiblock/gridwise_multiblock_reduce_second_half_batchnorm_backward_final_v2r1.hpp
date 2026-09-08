// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Info Technologies Ltd.

#pragma once

#include "ck/utility/data_type.hpp"
#include "ck/tensor_operation/gpu/block/reduction_functions_blockwise.hpp"
#include "ck/tensor_operation/gpu/thread/threadwise_welford.hpp"
#include "ck/tensor_operation/gpu/thread/threadwise_tensor_slice_transfer.hpp"
#include "ck/tensor_operation/gpu/element/element_wise_operation.hpp"

namespace ck {

template <typename GridwiseReduceSecondHalfBatchNormBackwardFinal_,
          typename XDataType,
          typename DyDataType,
          typename DxDataType,
          typename ScaleDataType,
          typename DscaleDbiasDataType,
          typename MeanVarDataType,
          typename DyElementwiseOp,
          typename XYGridDesc_K0_M_K100_K10_K11,
          typename DscaleDbiasGridDesc_M_K,
          typename MeanVarGridDesc_M,
          typename ScaleBiasGridDesc_M>
__global__ void
#if CK_USE_LAUNCH_BOUNDS
    __launch_bounds__(512, 2)
#endif
        kernel_reduce_second_half_batchnorm_backward_final_opt(
            const XYGridDesc_K0_M_K100_K10_K11 x_grid_desc_k0_m_k100_k10_k11,
            const XYGridDesc_K0_M_K100_K10_K11 dy_grid_desc_k0_m_k100_k10_k11,
            const XYGridDesc_K0_M_K100_K10_K11 dx_grid_desc_k0_m_k100_k10_k11,
            const DscaleDbiasGridDesc_M_K dscale_dbias_grid_desc_m_k,
            const MeanVarGridDesc_M mean_var_grid_desc_m,
            const ScaleBiasGridDesc_M scale_grid_desc_m,
            const ScaleBiasGridDesc_M bias_grid_desc_m,
            index_t blkgroup_size,
            long_index_t reduce_size,
            index_t num_xy_k_block_tile_iteration,
            index_t num_dscale_dbias_k_block_tile_iteration,
            const DscaleDbiasDataType* const __restrict__ p_reduce_dscale,
            const DscaleDbiasDataType* const __restrict__ p_reduce_dbias,
            const MeanVarDataType* const __restrict__ p_mean,
            const MeanVarDataType* const __restrict__ p_inv_var,
            const XDataType* const __restrict__ p_x,
            const DyDataType* const __restrict__ p_dy,
            const ScaleDataType* const __restrict__ p_scale,
            const DyElementwiseOp dy_elementwise_op,
            DxDataType* const __restrict__ p_dx,
            DscaleDbiasDataType* const __restrict__ p_dscale,
            DscaleDbiasDataType* const __restrict__ p_dbias)
{
    GridwiseReduceSecondHalfBatchNormBackwardFinal_::Run(x_grid_desc_k0_m_k100_k10_k11,
                                                         dy_grid_desc_k0_m_k100_k10_k11,
                                                         dx_grid_desc_k0_m_k100_k10_k11,
                                                         dscale_dbias_grid_desc_m_k,
                                                         mean_var_grid_desc_m,
                                                         scale_grid_desc_m,
                                                         bias_grid_desc_m,
                                                         blkgroup_size,
                                                         reduce_size,
                                                         num_xy_k_block_tile_iteration,
                                                         num_dscale_dbias_k_block_tile_iteration,
                                                         p_reduce_dscale,
                                                         p_reduce_dbias,
                                                         p_mean,
                                                         p_inv_var,
                                                         p_x,
                                                         p_dy,
                                                         p_scale,
                                                         dy_elementwise_op,
                                                         p_dx,
                                                         p_dscale,
                                                         p_dbias);
};

template <typename XDataType,
          typename DyDataType,
          typename DxDataType,
          typename AccDataType,
          typename ScaleDataType,
          typename DscaleDbiasDataType,
          typename MeanVarDataType,
          typename DyElementwiseOp,
          typename XYGridDesc_K0_M_K100_K10_K11,
          typename DscaleDbiasGridDesc_M_K,
          typename MeanVarGridDesc_M,
          typename ScaleBiasGridDesc_M,
          index_t BlockSize,
          index_t MThreadClusterSize,
          index_t KThreadClusterSize,
          index_t MThreadSliceSize,
          index_t KThreadSliceSize,
          index_t K10,
          index_t XDyDxVectorDim,
          index_t XSrcVectorSize,
          index_t DySrcVectorSize,
          index_t DxDstVectorSize,
          index_t ScaleSrcVectorSize,
          index_t DscaleDbiasDstVectorSize,
          index_t MeanVarSrcVectorSize>
struct GridwiseReduceSecondHalfBatchNormBackwardFinal_opt
{
    static_assert((XDyDxVectorDim == 4 && KThreadSliceSize % XSrcVectorSize == 0 &&
                   KThreadSliceSize % DySrcVectorSize == 0 &&
                   KThreadSliceSize % DxDstVectorSize == 0),
                  "Invalid thread slice sizes and/or vector sizes configuration, please check!");

    using ThreadClusterLengths_K0_M_K100_K10_K11 =
        Sequence<1, MThreadClusterSize, 1, 1, KThreadClusterSize>;

    using ThreadClusterArrangeOrder = Sequence<0, 1, 2, 3, 4>;

    using ThreadBufferDimAccessOrder = Sequence<0, 1, 2, 3, 4>;

    static constexpr auto thread_cluster_desc = make_cluster_descriptor(
        ThreadClusterLengths_K0_M_K100_K10_K11{}, ThreadClusterArrangeOrder{});

    using ThreadReduceSrcDesc_M_1 = decltype(
        make_naive_tensor_descriptor_packed(make_tuple(Number<MThreadSliceSize>{}, Number<1>{})));
    using ThreadReduceDstDesc_M =
        decltype(make_naive_tensor_descriptor_packed(make_tuple(Number<MThreadSliceSize>{})));

    using BlockwiseReduce =
        PartitionedBlockwiseReductionV1R1<AccDataType,
                                          BlockSize,
                                          ThreadClusterLengths_K0_M_K100_K10_K11,
                                          ThreadClusterArrangeOrder,
                                          ck::reduce::Add,
                                          false>;

    using ThreadwiseReduce = ThreadwiseReduction<AccDataType,
                                                 ThreadReduceSrcDesc_M_1,
                                                 ThreadReduceDstDesc_M,
                                                 ck::reduce::Add,
                                                 false>;

    using PassThroughOp = tensor_operation::element_wise::PassThrough;

    static constexpr auto I0 = Number<0>{};
    static constexpr auto I1 = Number<1>{};
    static constexpr auto I2 = Number<2>{};
    static constexpr auto I3 = Number<3>{};
    static constexpr auto I4 = Number<4>{};

    static constexpr index_t M_BlockTileSize = MThreadClusterSize * MThreadSliceSize;
    static constexpr index_t K_BlockTileSize = KThreadClusterSize * KThreadSliceSize * K10;

    // clang-format off
    // Two of the steps of Multiblock BatchNorm Backward
    // Step 1: Second half of Reduction: dbias = sum(dy), dscale = sum(dy * (x-mean) * inv-variance)
    // Step 2: calculating dx = 1/reduce_size * inv-variance * scale * (reduce_size * dy - dbias - dscale * (x - mean) * inv-variance)) elementwise-ly
    // clang-format on
    __device__ static void Run(const XYGridDesc_K0_M_K100_K10_K11& x_grid_desc_k0_m_k100_k10_k11,
                               const XYGridDesc_K0_M_K100_K10_K11& dy_grid_desc_k0_m_k100_k10_k11,
                               const XYGridDesc_K0_M_K100_K10_K11& dx_grid_desc_k0_m_k100_k10_k11,
                               const DscaleDbiasGridDesc_M_K& dscale_dbias_grid_desc_m_k,
                               const MeanVarGridDesc_M& mean_var_grid_desc_m,
                               const ScaleBiasGridDesc_M& scale_grid_desc_m,
                               const ScaleBiasGridDesc_M& dscale_dbias_grid_desc_m,
                               index_t blkgroup_size,
                               long_index_t reduce_size,
                               index_t num_xy_k_block_tile_iteration,
                               index_t num_dscale_dbias_k_block_tile_iteration,
                               const DscaleDbiasDataType* const __restrict__ p_reduce_dscale,
                               const DscaleDbiasDataType* const __restrict__ p_reduce_dbias,
                               const MeanVarDataType* const __restrict__ p_mean,
                               const MeanVarDataType* const __restrict__ p_inv_var,
                               const XDataType* const __restrict__ p_x,
                               const DyDataType* const __restrict__ p_dy,
                               const ScaleDataType* const __restrict__ p_scale,
                               const DyElementwiseOp dy_elementwise_op,
                               DxDataType* const __restrict__ p_dx,
                               DscaleDbiasDataType* const __restrict__ p_dscale,
                               DscaleDbiasDataType* const __restrict__ p_dbias)
    {
        __shared__ AccDataType p_reduce_work_buffer[BlockSize];

        auto reduce_work_buf =
            make_dynamic_buffer<AddressSpaceEnum::Lds>(p_reduce_work_buffer, BlockSize);

        StaticBuffer<AddressSpaceEnum::Vgpr, AccDataType, MThreadSliceSize * 1, true>
            reduce_dscale_thread_buf;
        StaticBuffer<AddressSpaceEnum::Vgpr, AccDataType, MThreadSliceSize * 1, true>
            reduce_dbias_thread_buf;

        StaticBuffer<AddressSpaceEnum::Vgpr, AccDataType, MThreadSliceSize, true> dscale_thread_buf;
        StaticBuffer<AddressSpaceEnum::Vgpr, AccDataType, MThreadSliceSize, true> dbias_thread_buf;

        StaticBuffer<AddressSpaceEnum::Vgpr,
                     AccDataType,
                     MThreadSliceSize * KThreadSliceSize * K10,
                     true>
            x_thread_buf;
        StaticBuffer<AddressSpaceEnum::Vgpr,
                     AccDataType,
                     MThreadSliceSize * KThreadSliceSize * K10,
                     true>
            dy_thread_buf;
        StaticBuffer<AddressSpaceEnum::Vgpr,
                     AccDataType,
                     MThreadSliceSize * KThreadSliceSize * K10,
                     true>
            dx_thread_buf;

        StaticBuffer<AddressSpaceEnum::Vgpr, AccDataType, MThreadSliceSize, true> mean_thread_buf;
        StaticBuffer<AddressSpaceEnum::Vgpr, AccDataType, MThreadSliceSize, true>
            inv_var_thread_buf;
        StaticBuffer<AddressSpaceEnum::Vgpr, AccDataType, MThreadSliceSize, true> scale_thread_buf;

        const index_t thread_local_id = get_thread_local_1d_id();
        const index_t block_global_id = get_block_1d_id();
        const index_t blkgroup_id     = block_global_id / blkgroup_size;
        const index_t block_local_id  = block_global_id % blkgroup_size;

        const auto thread_cluster_idx =
            thread_cluster_desc.CalculateBottomIndex(make_multi_index(thread_local_id));

        const auto thread_m_cluster_id = thread_cluster_idx[I1];
        const auto thread_k_cluster_id = thread_cluster_idx[I4];

        using ThreadBufferLengths_K0_M_K100_K10_K11 = Sequence<1, 1, 1, 1, KThreadSliceSize>;
        using ThreadBufferLengths_M                 = Sequence<MThreadSliceSize>;
        using ThreadBufferLengths_M_1               = Sequence<MThreadSliceSize, 1>;
        constexpr auto thread_buffer_desc_k0_m_k100_k10_k11 =
            make_naive_tensor_descriptor_packed(make_tuple(Number<1>{},
                                                           Number<MThreadSliceSize>{},
                                                           Number<1>{},
                                                           Number<K10>{},
                                                           Number<KThreadSliceSize>{}));
        constexpr auto thread_buffer_desc_m =
            make_naive_tensor_descriptor_packed(make_tuple(Number<MThreadSliceSize>{}));
        constexpr auto thread_buffer_desc_m_1 = make_naive_tensor_descriptor_packed(
            make_tuple(Number<MThreadSliceSize>{}, Number<1>{}));

        // clang-format off
        // Step 1: do final reduction of dbias = sum(dy), dscale = sum(dy * (x-mean) * inv-variance)
        // clang-format on

        auto threadwise_dscale_dbias_load_m_k =
            ThreadwiseTensorSliceTransfer_v2<DscaleDbiasDataType,
                                             AccDataType,
                                             DscaleDbiasGridDesc_M_K,
                                             decltype(thread_buffer_desc_m_1),
                                             ThreadBufferLengths_M_1,
                                             Sequence<0, 1>,
                                             1,
                                             1,
                                             1,
                                             true>(
                dscale_dbias_grid_desc_m_k,
                make_multi_index(blkgroup_id * M_BlockTileSize +
                                     thread_m_cluster_id * MThreadSliceSize,
                                 thread_k_cluster_id * 1));

        auto threadwise_dscale_dbias_store_m =
            ThreadwiseTensorSliceTransfer_v1r3<AccDataType,
                                               DscaleDbiasDataType,
                                               decltype(thread_buffer_desc_m),
                                               ScaleBiasGridDesc_M,
                                               PassThroughOp,
                                               ThreadBufferLengths_M,
                                               Sequence<0>,
                                               0,
                                               DscaleDbiasDstVectorSize,
                                               InMemoryDataOperationEnum::Set,
                                               1,
                                               true>(
                dscale_dbias_grid_desc_m,
                make_multi_index(blkgroup_id * M_BlockTileSize +
                                 thread_m_cluster_id * MThreadSliceSize),
                PassThroughOp{});

        const auto reduce_dscale_global_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            p_reduce_dscale, dscale_dbias_grid_desc_m_k.GetElementSpaceSize());

        const auto reduce_dbias_global_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            p_reduce_dbias, dscale_dbias_grid_desc_m_k.GetElementSpaceSize());

        auto dscale_global_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            p_dscale, dscale_dbias_grid_desc_m.GetElementSpaceSize());

        auto dbias_global_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            p_dbias, dscale_dbias_grid_desc_m.GetElementSpaceSize());

        constexpr auto dscale_dbias_thread_copy_step_m_k =
            make_multi_index(0, KThreadClusterSize * 1);

        static_for<0, MThreadSliceSize, 1>{}([&](auto I) {
            dscale_thread_buf(I) = type_convert<AccDataType>(0.0f);
            dbias_thread_buf(I)  = type_convert<AccDataType>(0.0f);
        });

        for(index_t reducedTiles = 0; reducedTiles < num_dscale_dbias_k_block_tile_iteration;
            ++reducedTiles)
        {
            threadwise_dscale_dbias_load_m_k.Run(dscale_dbias_grid_desc_m_k,
                                                 reduce_dscale_global_buf,
                                                 thread_buffer_desc_m_1,
                                                 make_tuple(I0, I0),
                                                 reduce_dscale_thread_buf);

            threadwise_dscale_dbias_load_m_k.Run(dscale_dbias_grid_desc_m_k,
                                                 reduce_dbias_global_buf,
                                                 thread_buffer_desc_m_1,
                                                 make_tuple(I0, I0),
                                                 reduce_dbias_thread_buf);

            ThreadwiseReduce::Reduce(reduce_dscale_thread_buf, dscale_thread_buf);
            ThreadwiseReduce::Reduce(reduce_dbias_thread_buf, dbias_thread_buf);

            threadwise_dscale_dbias_load_m_k.MoveSrcSliceWindow(dscale_dbias_grid_desc_m_k,
                                                                dscale_dbias_thread_copy_step_m_k);
        }

        static_for<0, MThreadSliceSize, 1>{}([&](auto I) {
            if constexpr(I > 0)
                block_sync_lds();
            BlockwiseReduce::Reduce(reduce_work_buf, dscale_thread_buf(I));
            block_sync_lds();
            BlockwiseReduce::Reduce(reduce_work_buf, dbias_thread_buf(I));
        });
        threadwise_dscale_dbias_store_m.Run(thread_buffer_desc_m,
                                            make_tuple(I0),
                                            dscale_thread_buf,
                                            dscale_dbias_grid_desc_m,
                                            dscale_global_buf);

        threadwise_dscale_dbias_store_m.Run(thread_buffer_desc_m,
                                            make_tuple(I0),
                                            dbias_thread_buf,
                                            dscale_dbias_grid_desc_m,
                                            dbias_global_buf);

        // clang-format off
        // Step 2: calculate dx = 1/N * inv-variance * scale * (N * dy - dbias - dscale * (x - mean) * inv-variance)
        // clang-format on

        // const index_t workSizePerBlock = K_BlockTileSize * num_xy_k_block_tile_iteration;

        AccDataType inv_reduce_size =
            type_convert<AccDataType>(1.0) / type_convert<AccDataType>(reduce_size);

        const auto x_global_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            p_x, x_grid_desc_k0_m_k100_k10_k11.GetElementSpaceSize());

        const auto dy_global_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            p_dy, dy_grid_desc_k0_m_k100_k10_k11.GetElementSpaceSize());

        auto dx_global_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            p_dx, dx_grid_desc_k0_m_k100_k10_k11.GetElementSpaceSize());

        const auto scale_global_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            p_scale, scale_grid_desc_m.GetElementSpaceSize());

        const auto mean_global_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            p_mean, mean_var_grid_desc_m.GetElementSpaceSize());

        const auto inv_var_global_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            p_inv_var, mean_var_grid_desc_m.GetElementSpaceSize());

        auto threadwise_scale_load =
            ThreadwiseTensorSliceTransfer_v2<ScaleDataType,
                                             AccDataType,
                                             ScaleBiasGridDesc_M,
                                             decltype(thread_buffer_desc_m),
                                             ThreadBufferLengths_M,
                                             Sequence<0>,
                                             0,
                                             ScaleSrcVectorSize,
                                             1,
                                             true>(
                scale_grid_desc_m,
                make_multi_index(blkgroup_id * M_BlockTileSize +
                                 thread_m_cluster_id * MThreadSliceSize));

        auto threadwise_mean_var_load =
            ThreadwiseTensorSliceTransfer_v2<MeanVarDataType,
                                             AccDataType,
                                             MeanVarGridDesc_M,
                                             decltype(thread_buffer_desc_m),
                                             ThreadBufferLengths_M,
                                             Sequence<0>,
                                             0,
                                             MeanVarSrcVectorSize,
                                             1,
                                             true>(
                mean_var_grid_desc_m,
                make_multi_index(blkgroup_id * M_BlockTileSize +
                                 thread_m_cluster_id * MThreadSliceSize));

        threadwise_scale_load.Run(scale_grid_desc_m,
                                  scale_global_buf,
                                  thread_buffer_desc_m,
                                  make_tuple(I0),
                                  scale_thread_buf);

        threadwise_mean_var_load.Run(mean_var_grid_desc_m,
                                     mean_global_buf,
                                     thread_buffer_desc_m,
                                     make_tuple(I0),
                                     mean_thread_buf);

        threadwise_mean_var_load.Run(mean_var_grid_desc_m,
                                     inv_var_global_buf,
                                     thread_buffer_desc_m,
                                     make_tuple(I0),
                                     inv_var_thread_buf);

        auto threadwise_x_load =
            ThreadwiseTensorSliceTransfer_v2<XDataType,
                                             AccDataType,
                                             XYGridDesc_K0_M_K100_K10_K11,
                                             decltype(thread_buffer_desc_k0_m_k100_k10_k11),
                                             ThreadBufferLengths_K0_M_K100_K10_K11,
                                             ThreadBufferDimAccessOrder,
                                             XDyDxVectorDim,
                                             XSrcVectorSize,
                                             1,
                                             true>(
                x_grid_desc_k0_m_k100_k10_k11,
                make_multi_index(block_local_id,
                                 blkgroup_id * M_BlockTileSize +
                                     thread_m_cluster_id * MThreadSliceSize,
                                 0,
                                 0,
                                 thread_k_cluster_id * XSrcVectorSize));

        auto threadwise_dy_load =
            ThreadwiseTensorSliceTransfer_v2<DyDataType,
                                             AccDataType,
                                             XYGridDesc_K0_M_K100_K10_K11,
                                             decltype(thread_buffer_desc_k0_m_k100_k10_k11),
                                             ThreadBufferLengths_K0_M_K100_K10_K11,
                                             ThreadBufferDimAccessOrder,
                                             XDyDxVectorDim,
                                             DySrcVectorSize,
                                             1,
                                             true>(
                dy_grid_desc_k0_m_k100_k10_k11,
                make_multi_index(block_local_id,
                                 blkgroup_id * M_BlockTileSize +
                                     thread_m_cluster_id * MThreadSliceSize,
                                 0,
                                 0,
                                 thread_k_cluster_id * DySrcVectorSize));

        auto threadwise_dx_store =
            ThreadwiseTensorSliceTransfer_v1r3<AccDataType,
                                               DxDataType,
                                               decltype(thread_buffer_desc_k0_m_k100_k10_k11),
                                               XYGridDesc_K0_M_K100_K10_K11,
                                               PassThroughOp,
                                               ThreadBufferLengths_K0_M_K100_K10_K11,
                                               ThreadBufferDimAccessOrder,
                                               XDyDxVectorDim,
                                               DxDstVectorSize,
                                               InMemoryDataOperationEnum::Set,
                                               1,
                                               true>(
                dx_grid_desc_k0_m_k100_k10_k11,
                make_multi_index(block_local_id,
                                 blkgroup_id * M_BlockTileSize +
                                     thread_m_cluster_id * MThreadSliceSize,
                                 0,
                                 0,
                                 thread_k_cluster_id * DxDstVectorSize),
                PassThroughOp{});

        constexpr auto xy_thread_copy_step_m_k = make_multi_index(0, -MThreadSliceSize, 0, 1, 0);
        constexpr auto xy_thread_copy_step_m   = make_multi_index(0, 1, 0, 0, 0);
        constexpr auto xy_thread_copy_step_reduce_tiles = make_multi_index(0, 0, 1, -K10, 0);
        for(index_t reducedTiles = 0; reducedTiles < num_xy_k_block_tile_iteration; ++reducedTiles)
        {
            // #pragma unroll
            // for(index_t iK10=0; iK10< K10; ++iK10){
            static_for<0, K10, 1>{}([&](auto iK10) {
                static_for<0, MThreadSliceSize, 1>{}([&](auto iM) {
                    threadwise_x_load.Run(x_grid_desc_k0_m_k100_k10_k11,
                                          x_global_buf,
                                          thread_buffer_desc_k0_m_k100_k10_k11,
                                          make_tuple(I0, iM, I0, iK10, I0),
                                          x_thread_buf);

                    threadwise_dy_load.Run(dy_grid_desc_k0_m_k100_k10_k11,
                                           dy_global_buf,
                                           thread_buffer_desc_k0_m_k100_k10_k11,
                                           make_tuple(I0, iM, I0, iK10, I0),
                                           dy_thread_buf);

                    AccDataType multiplier =
                        inv_reduce_size * inv_var_thread_buf[iM] * scale_thread_buf[iM];

                    static_for<0, KThreadSliceSize, 1>{}([&](auto iK) {
                        constexpr auto offset =
                            thread_buffer_desc_k0_m_k100_k10_k11.CalculateOffset(
                                make_tuple(0, iM, 0, iK10, iK));
                        dy_elementwise_op(dy_thread_buf(Number<offset>{}),
                                          dy_thread_buf[Number<offset>{}]);

                        AccDataType norm_x =
                            (x_thread_buf[Number<offset>{}] - mean_thread_buf[iM]) *
                            inv_var_thread_buf[iM];

                        AccDataType tmpVal = norm_x * dscale_thread_buf[iM];

                        dx_thread_buf(Number<offset>{}) =
                            multiplier * (type_convert<AccDataType>(reduce_size) *
                                              dy_thread_buf[Number<offset>{}] -
                                          dbias_thread_buf[iM] - tmpVal);
                    });
                    threadwise_dx_store.Run(thread_buffer_desc_k0_m_k100_k10_k11,
                                            make_tuple(I0, iM, I0, iK10, I0),
                                            dx_thread_buf,
                                            dx_grid_desc_k0_m_k100_k10_k11,
                                            dx_global_buf);
                    threadwise_x_load.MoveSrcSliceWindow(x_grid_desc_k0_m_k100_k10_k11,
                                                         xy_thread_copy_step_m);
                    threadwise_dy_load.MoveSrcSliceWindow(dy_grid_desc_k0_m_k100_k10_k11,
                                                          xy_thread_copy_step_m);
                    threadwise_dx_store.MoveDstSliceWindow(dx_grid_desc_k0_m_k100_k10_k11,
                                                           xy_thread_copy_step_m);
                });

                threadwise_x_load.MoveSrcSliceWindow(x_grid_desc_k0_m_k100_k10_k11,
                                                     xy_thread_copy_step_m_k);
                threadwise_dy_load.MoveSrcSliceWindow(dy_grid_desc_k0_m_k100_k10_k11,
                                                      xy_thread_copy_step_m_k);
                threadwise_dx_store.MoveDstSliceWindow(dx_grid_desc_k0_m_k100_k10_k11,
                                                       xy_thread_copy_step_m_k);
            });

            threadwise_x_load.MoveSrcSliceWindow(x_grid_desc_k0_m_k100_k10_k11,
                                                 xy_thread_copy_step_reduce_tiles);
            threadwise_dy_load.MoveSrcSliceWindow(dy_grid_desc_k0_m_k100_k10_k11,
                                                  xy_thread_copy_step_reduce_tiles);
            threadwise_dx_store.MoveDstSliceWindow(dx_grid_desc_k0_m_k100_k10_k11,
                                                   xy_thread_copy_step_reduce_tiles);
        }
    };
};

} // namespace ck
