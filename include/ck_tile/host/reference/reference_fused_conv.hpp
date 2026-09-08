// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include <iostream>
#include <type_traits>
#include <sstream>

#include "ck_tile/core.hpp"
#include "ck_tile/host.hpp"

namespace ck_tile {

//
// @brief      Reference implementation for forward convolution.
//
// @paragraph
//             HostTensor descriptor in GNCHW/GKCXY/GNKHW dimensional order
//             Supports both GNCHW/NGCHW as well as GNHWC/NHWGC physical layout
//             as long as dimensions in tensor descriptor is in GNCHW order
//
// @tparam     InDataType               Input tensor data type.
// @tparam     WeiDataType              Weights tensor data type.
// @tparam     OutDataType              Output tensor data type.
// @tparam     InElementwiseOperation   Functor for input tensor elementwise
//                                      operation.
// @tparam     WeiElementwiseOperation  Functor for weights tensor elementwise
//                                      operation.
// @tparam     NDimSpatial  Number of spatial dimensions.
//
// input descriptor in [G, N, C, Do, Ho, Wo] order
// weight descriptor in [G, K, C, Z, Y, X] order
// output descriptor in [G, N, K, Di, Hi, Wi] order
// phyiscal layout is irrelavent
template <index_t NDimSpatial,
          typename InDataType,
          typename WeiDataType,
          typename OutDataType,
          typename BiasDataType,
          typename InElementwiseOperation,
          typename WeiElementwiseOperation,
          typename OutElementwiseOperation,
          typename std::enable_if<NDimSpatial >= 1 && NDimSpatial <= 3, bool>::type = false>
struct ReferenceFusedConv
{
    // Argument
    struct Argument
    {
        Argument(const HostTensor<InDataType>& input,
                 const HostTensor<WeiDataType>& weight,
                 HostTensor<OutDataType>& output,
                 const HostTensor<BiasDataType>& bias,
                 const HostTensor<OutDataType>& res,
                 std::vector<long_index_t> conv_filter_strides,
                 std::vector<long_index_t> conv_filter_dilations,
                 std::vector<long_index_t> input_left_pads,
                 std::vector<long_index_t> input_right_pads,
                 InElementwiseOperation in_element_op,
                 WeiElementwiseOperation wei_element_op,
                 OutElementwiseOperation out_element_op)
            : input_{input},
              weight_{weight},
              output_{output},
              bias_{bias},
              res_{res},
              conv_strides_{conv_filter_strides},
              conv_dilations_{conv_filter_dilations},
              in_left_pads_{input_left_pads},
              in_right_pads_{input_right_pads},
              in_element_op_{in_element_op},
              wei_element_op_{wei_element_op},
              out_element_op_{out_element_op}
        {
        }

        const HostTensor<InDataType>& input_;
        const HostTensor<WeiDataType>& weight_;
        HostTensor<OutDataType>& output_;
        const HostTensor<BiasDataType>& bias_;
        const HostTensor<OutDataType>& res_;

        std::vector<long_index_t> conv_strides_;
        std::vector<long_index_t> conv_dilations_;
        std::vector<long_index_t> in_left_pads_;
        std::vector<long_index_t> in_right_pads_;

        InElementwiseOperation in_element_op_;
        WeiElementwiseOperation wei_element_op_;
        OutElementwiseOperation out_element_op_;
    };

    struct Invoker
    {
        using Argument = ReferenceFusedConv::Argument;

        float Run(const Argument& arg, bool SkipRelu = false)
        {
            if(arg.input_.get_num_of_dimension() == NDimSpatial + 3 &&
               arg.weight_.get_num_of_dimension() == NDimSpatial + 3 &&
               arg.output_.get_num_of_dimension() == NDimSpatial + 3)
            {
                if constexpr(NDimSpatial == 2)
                {
                    auto func = [&](auto g, auto n, auto k, auto ho, auto wo) {
                        float v_acc = 0;

                        for(std::size_t c = 0; c < arg.weight_.get_lengths()[2]; ++c)
                        {
                            for(std::size_t y = 0; y < arg.weight_.get_lengths()[3]; ++y)
                            {
                                auto hi = static_cast<long_index_t>(ho * arg.conv_strides_[0]) +
                                          static_cast<long_index_t>(y * arg.conv_dilations_[0]) -
                                          static_cast<long_index_t>(arg.in_left_pads_[0]);

                                for(std::size_t x = 0; x < arg.weight_.get_lengths()[4]; ++x)
                                {
                                    auto wi =
                                        static_cast<long_index_t>(wo * arg.conv_strides_[1]) +
                                        static_cast<long_index_t>(x * arg.conv_dilations_[1]) -
                                        static_cast<long_index_t>(arg.in_left_pads_[1]);

                                    if(hi >= 0 &&
                                       type_convert<std::size_t>(hi) <
                                           arg.input_.get_lengths()[3] &&
                                       wi >= 0 &&
                                       type_convert<std::size_t>(wi) < arg.input_.get_lengths()[4])
                                    {
                                        float v_in;
                                        float v_wei;

                                        arg.in_element_op_(
                                            v_in, type_convert<float>(arg.input_(g, n, c, hi, wi)));

                                        arg.wei_element_op_(
                                            v_wei, type_convert<float>(arg.weight_(g, k, c, y, x)));

                                        v_acc += v_in * v_wei;
                                    }
                                }
                            }
                        }

                        float v_out = v_acc + type_convert<float>(arg.bias_(g, k)) +
                                      type_convert<float>(arg.res_(g, n, k, ho, wo));

                        if(!SkipRelu)
                        {
                            v_out = v_out >= 0.0f ? v_out : 0.0f;
                        }

                        arg.output_(g, n, k, ho, wo) = type_convert<OutDataType>(v_out);
                    };

                    make_ParallelTensorFunctor(func,
                                               arg.output_.get_lengths()[0],
                                               arg.output_.get_lengths()[1],
                                               arg.output_.get_lengths()[2],
                                               arg.output_.get_lengths()[3],
                                               arg.output_.get_lengths()[4])(
                        std::thread::hardware_concurrency());

                    return 0;
                }
            }
            else if(arg.input_.get_num_of_dimension() == NDimSpatial + 4 &&
                    arg.weight_.get_num_of_dimension() == NDimSpatial + 4 &&
                    arg.output_.get_num_of_dimension() == NDimSpatial + 4)
            {
                if constexpr(NDimSpatial == 2)
                {
                    const index_t Kx = arg.output_.get_lengths()[5];

                    auto func = [&](auto g, auto n, auto k, auto ho, auto wo, auto kx) {
                        float v_acc = 0;

                        for(std::size_t c = 0; c < arg.weight_.get_lengths()[2]; ++c)
                        {
                            for(std::size_t cx = 0; cx < arg.weight_.get_lengths()[5]; ++cx)
                            {
                                for(std::size_t y = 0; y < arg.weight_.get_lengths()[3]; ++y)
                                {
                                    auto hi =
                                        static_cast<long_index_t>(ho * arg.conv_strides_[0]) +
                                        static_cast<long_index_t>(y * arg.conv_dilations_[0]) -
                                        static_cast<long_index_t>(arg.in_left_pads_[0]);

                                    for(std::size_t x = 0; x < arg.weight_.get_lengths()[4]; ++x)
                                    {
                                        auto wi =
                                            static_cast<long_index_t>(wo * arg.conv_strides_[1]) +
                                            static_cast<long_index_t>(x * arg.conv_dilations_[1]) -
                                            static_cast<long_index_t>(arg.in_left_pads_[1]);

                                        if(hi >= 0 &&
                                           type_convert<std::size_t>(hi) <
                                               arg.input_.get_lengths()[3] &&
                                           wi >= 0 &&
                                           type_convert<std::size_t>(wi) <
                                               arg.input_.get_lengths()[4])
                                        {
                                            float v_in;
                                            float v_wei;

                                            arg.in_element_op_(v_in,
                                                               type_convert<float>(arg.input_(
                                                                   g, n, c, hi, wi, cx)));

                                            arg.wei_element_op_(v_wei,
                                                                type_convert<float>(arg.weight_(
                                                                    g, k * Kx + kx, c, y, x, cx)));

                                            v_acc += v_in * v_wei;
                                        }
                                    }
                                }
                            }
                        }

                        float v_out = v_acc + type_convert<float>(arg.bias_(g, k * Kx + kx)) +
                                      type_convert<float>(arg.res_(g, n, k, ho, wo, kx));
                        if(!SkipRelu)
                        {
                            v_out = v_out >= 0.0f ? v_out : 0.0f;
                        }

                        arg.output_(g, n, k, ho, wo, kx) = type_convert<OutDataType>(v_out);
                    };

                    make_ParallelTensorFunctor(func,
                                               arg.output_.get_lengths()[0],
                                               arg.output_.get_lengths()[1],
                                               arg.output_.get_lengths()[2],
                                               arg.output_.get_lengths()[3],
                                               arg.output_.get_lengths()[4],
                                               arg.output_.get_lengths()[5])(
                        std::thread::hardware_concurrency());

                    return 0;
                }
            }
            else
            {
                throw std::runtime_error("wrong! inconsistent dimension");
            }
        }
    };

    static constexpr bool IsValidCompilationParameter()
    {
        // TODO: properly implement this check
        return true;
    }

    static auto MakeArgument(const HostTensor<InDataType>& input,
                             const HostTensor<WeiDataType>& weight,
                             HostTensor<OutDataType>& output,
                             const HostTensor<BiasDataType>& bias,
                             const HostTensor<OutDataType>& res,
                             std::vector<long_index_t> conv_filter_strides,
                             std::vector<long_index_t> conv_filter_dilations,
                             std::vector<long_index_t> input_left_pads,
                             std::vector<long_index_t> input_right_pads,
                             InElementwiseOperation in_element_op,
                             WeiElementwiseOperation wei_element_op,
                             OutElementwiseOperation out_element_op)
    {
        return Argument{input,
                        weight,
                        output,
                        bias,
                        res,
                        conv_filter_strides,
                        conv_filter_dilations,
                        input_left_pads,
                        input_right_pads,
                        in_element_op,
                        wei_element_op,
                        out_element_op};
    }

    static auto MakeInvoker() { return Invoker{}; }

    std::string GetTypeString() const
    {
        auto str = std::stringstream();

        // clang-format off
        str << "ReferenceFusedConv"
            << std::endl;
        // clang-format on

        return str.str();
    }
};

} // namespace ck_tile
