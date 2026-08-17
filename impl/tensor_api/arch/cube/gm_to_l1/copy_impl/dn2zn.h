/**
 * Copyright (c) 2026 Huawei Technologies Co., Ltd.
 * This program is free software, you can redistribute it and/or modify it under the terms and conditions of
 * CANN Open Software License Agreement Version 2.0 (the "License").
 * Please refer to the License for details. You may not use this file except in compliance with the License.
 * THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND, EITHER EXPRESS OR IMPLIED,
 * INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY, OR FITNESS FOR A PARTICULAR PURPOSE.
 * See LICENSE in the root of the software repository for the full text of the License.
 */

#if !defined(ASCENDC_TENSOR_API_INCLUDE_COMPILER_INTERNAL_HEADERS)
#warning                                                                                                               \
    "impl/tensor_api/arch/cube/gm_to_l1/copy_impl/dn2zn.h is an internal header file and must not be used directly. Functions or variables defined in this file maybe removed in the future. Please use "#include "tensor_api/tensor.h"" and use public functions or variables defined in interface headers files."
#define ASCENDC_TENSOR_API_INCLUDE_COMPILER_INTERNAL_HEADERS
#define UNDEF_ASCENDC_TENSOR_API_INCLUDE_COMPILER_INTERNAL_HEADERS_ASCENDC
#endif

/*!
 * \file dn2zn.h
 * \brief
 */
#ifndef IMPL_TENSOR_API_ARCH_CUBE_GM_TO_L1_COPY_IMPL_DN2ZN_H
#define IMPL_TENSOR_API_ARCH_CUBE_GM_TO_L1_COPY_IMPL_DN2ZN_H

#include "impl/tensor_api/arch/cube/gm_to_l1/copy_impl/copy_common.h"

namespace asc {
namespace te {

class copy_gm_to_l1_dn2zn {
public:
    template <const copy_gm_to_l1_trait& trait, typename T, typename U>
    __aicore__ inline static void run(const T& dst, const U& src)
    {
        if constexpr (U::layout_type::depth == THREE_DIM_DATA || U::layout_type::depth == FIVE_DIM_DATA) {
            TENSOR_API_DEBUG_CHECK(debug_check_batch_count, get<0>(src.layout().shape()), "copy_gm_to_l1 dn2zn path");
        }
        run_gm_to_l1_batched<trait, copy_gm_to_l1_dn2zn, T, U>(dst, src);
    }

    template <const copy_gm_to_l1_trait& trait, typename T, typename U, typename DstCoord, typename SrcCoord, typename ShapeType>
    __aicore__ inline static void run(
        const T& dst, const U& src, const DstCoord& coord_dst, const SrcCoord& coord_src, const ShapeType& copy_shape)
    {
        run_gm_to_l1_batched<trait, copy_gm_to_l1_dn2zn, T, U>(dst, src, coord_dst, coord_src, copy_shape);
    }

    template <const copy_gm_to_l1_trait& trait, typename T, typename U>
    __aicore__ inline static constexpr void check_template()
    {
        check_layout_pattern<U, T>();
        check_data_type::check_gm_to_l1_fp4_data_type<T, U>();
    }

    // Extracts single-matrix parameters from the (batch-stripped) src/dst layouts and emits the
    // instruction. dn_num/src_dn_matrix_stride/dst_nz_matrix_stride carry the batch dimension (1/0/0 when
    // there is no batch). The src/dst pattern is read from the original tensor type U/T.
    template <typename T, typename U, typename SrcLayout, typename DstLayout>
    __aicore__ inline static void emit_copy(const T& dst, const U& src, const SrcLayout& src_layout,
                                           const DstLayout& dst_layout, uint16_t dn_num,
                                           uint64_t src_dn_matrix_stride, uint32_t dst_nz_matrix_stride)
    {
        using type = typename U::element_type;

        uint16_t n_value;
        uint32_t d_value;
        uint32_t src_row_stride;
        if constexpr (is_satisfied_ptn_format_v<U, dn_layout_ptn>) {
            n_value = get_element<attr_info::shape, attr_info::column>(src_layout);
            d_value = get_element<attr_info::shape, attr_info::row>(src_layout);
            src_row_stride = get_element<attr_info::stride, attr_info::column>(src_layout);
        } else {
            n_value = get_element<attr_info::shape, attr_info::column, 1>(src_layout);
            d_value = get_element<attr_info::shape, attr_info::row, 1>(src_layout);
            src_row_stride = get_element<attr_info::stride, attr_info::column, 1>(src_layout);
        }
        auto dst_row_stride = get_element<attr_info::stride, attr_info::row, 1>(dst_layout);
        if constexpr (is_b4_type<type>) {
            // move fp4 as b8, need to be divided by 2
            d_value = d_value >> 1;
            src_row_stride = src_row_stride >> 1;
            src_dn_matrix_stride = src_dn_matrix_stride >> 1;
        }

        uint64_t src_d_value = src_row_stride;
        uint16_t dst_nz_c0_stride = dst_row_stride / C0_ELEMENT<type>;
        uint16_t dst_nz_n_stride = 1;

        uint64_t loop1_src_stride = src_d_value * sizeof(type);
        uint64_t loop4_src_stride = src_dn_matrix_stride * sizeof(type);

        uint16_t loop2_dst_stride = dst_nz_n_stride;  // loop2_dst_stride = dst_nz_n_stride
        uint16_t loop3_dst_stride = dst_nz_c0_stride; // loop3_dst_stride = dst_nz_c0_stride
        // loop4_dst_stride : dst_nz_matrix_stride * size_of_dst_type / C0_SIZE
        uint16_t loop4_dst_stride = static_cast<uint16_t>(dst_nz_matrix_stride / C0_ELEMENT<type>);

        uint8_t cache_mode = src.engine().get_cache_mode();

        copy_gm_to_l1_multi_nd2nz_instr::data_copy(dst.data().get(), src.data().get(), dn_num, loop2_dst_stride, loop3_dst_stride, loop4_dst_stride,
                                              loop1_src_stride, cache_mode, n_value, d_value, loop4_src_stride, false);
    }

    template <typename T, typename U, typename ShapeType, typename DstOffset, typename SrcOffset>
    __aicore__ inline static void emit_copy(const T& dst, const U& src, const ShapeType& copy_shape, uint16_t dn_num,
        uint64_t src_dn_matrix_stride, uint32_t dst_nz_matrix_stride, const DstOffset& dst_offset,
        const SrcOffset& src_offset)
    {
        using type = typename U::element_type;
        uint16_t n_value = get_shape_columns(copy_shape);
        uint32_t d_value = get_shape_rows(copy_shape);
        uint32_t src_col_stride = get_matrix_element<attr_info::stride, attr_info::column, 1>(src.layout());
        uint16_t loop3_dst_stride = get_matrix_element<attr_info::stride, attr_info::row, 1>(dst.layout()) /
            C0_ELEMENT<type>;
        if constexpr (is_b4_type<type>) {
            d_value >>= 1;
            src_col_stride >>= 1;
            src_dn_matrix_stride >>= 1;
        }
        uint64_t loop1_src_stride = src_col_stride * sizeof(type);
        uint64_t loop4_src_stride = src_dn_matrix_stride * sizeof(type);
        uint16_t loop4_dst_stride = static_cast<uint16_t>(dst_nz_matrix_stride / C0_ELEMENT<type>);
        copy_gm_to_l1_multi_nd2nz_instr::data_copy_with_offset(dst, src, dst_offset, src_offset, dn_num, 1, loop3_dst_stride,
            loop4_dst_stride, loop1_src_stride, src.engine().get_cache_mode(), n_value, d_value, loop4_src_stride, false);
    }
};

} // namespace te
} // namespace asc

#endif

#if defined(UNDEF_ASCENDC_TENSOR_API_INCLUDE_COMPILER_INTERNAL_HEADERS_ASCENDC)
#undef ASCENDC_TENSOR_API_INCLUDE_COMPILER_INTERNAL_HEADERS
#undef UNDEF_ASCENDC_TENSOR_API_INCLUDE_COMPILER_INTERNAL_HEADERS_ASCENDC
#endif
