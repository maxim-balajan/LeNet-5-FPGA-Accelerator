// SPDX-License-Identifier: GPL-3.0-only
/*
 * A hardware accelerated LeNet-5 architecture integrated to be accessible
 * by the processing system (CPU) of an FPGA.
 * Copyright (C) 2025  Markus Elias Gerber
 * Copyright (C) 2025  Maxim Balajan
 * 
 * This program is free software: you can redistribute it and/or modify
 * it under the terms of the GNU General Public License as published by
 * the Free Software Foundation, either version 3 of the License, or
 * (at your option) any later version.
 * 
 * This program is distributed in the hope that it will be useful,
 * but WITHOUT ANY WARRANTY; without even the implied warranty of
 * MERCHANTABILITY or FITNESS FOR A PARTICULAR PURPOSE.  See the
 * GNU General Public License for more details.
 * 
 * You should have received a copy of the GNU General Public License
 * along with this program.  If not, see <https://www.gnu.org/licenses/>.
 */
#pragma once
#include "quant_convolution.h"
#include "../data/data_converter.h"

#include <cmath>
#include <cstdint>
#include <iostream>

template<typename T, typename ACC>
QuantConvolution<T, ACC>::QuantConvolution(Matrix<T> kernel, Matrix<T> bias, Matrix<T> output_buffer, float s_b, float s_x, float s_w, float s_y)
    : kernel(kernel)
    , bias(bias)
    , output_buffer(output_buffer)
    , s_b(s_b)
    , s_x(s_x)
    , s_w(s_w)
    , s_y(s_y)
    , s_x_shift(log2((s_y / (s_x * s_w))) == std::numeric_limits<float>::infinity() ? std::numeric_limits<uint8_t>::max() : static_cast<uint8_t>(log2(s_y / (s_x * s_w))))
    , s_b_shift(log2(s_y / s_b) == std::numeric_limits<float>::infinity() ? std::numeric_limits<uint8_t>::max() : static_cast<uint8_t>(log2(s_y / s_b))) {
        // make sure the values are really a power of 2
        assert(log2((s_y / (s_x * s_w))) == std::numeric_limits<float>::infinity() || log2(s_y / (s_x * s_w)) == static_cast<float>(s_x_shift));
        assert(log2(s_y / s_b) == std::numeric_limits<float>::infinity() || log2(s_y / s_b) == static_cast<float>(s_b_shift));
    }

template<typename T, typename ACC>
QuantConvolution<T, ACC>::QuantConvolution(Matrix<T> kernel, Matrix<T> bias, size_t batching, size_t x, size_t y, size_t output_channel, float s_b, float s_x, float s_w, float s_y)
    : QuantConvolution(kernel, bias, Matrix<T>({batching, output_channel, x, y}), s_b, s_x, s_w, s_y) {}

namespace {
    template<typename ACC>
    inline ACC relu_ACC(ACC val) {
        return val < convert_data<float, ACC>(0.0f) ? convert_data<float, ACC>(0.0f) : val;
    }
}

template<typename T, typename ACC>
const Matrix<T>& QuantConvolution<T, ACC>::calc(const Matrix<T>& input) {

    Matrix<ACC> t(output_buffer.shape());

    for (size_t batch_id = 0; batch_id < input.shape()[0]; batch_id++)
    {
        // Compute Convolution of quantized input, quantized bias and quantized weight matrix
        for (size_t inch_id = 0; inch_id < input.shape()[1]; inch_id++)
        {
            for (size_t outch_id = 0; outch_id < kernel.shape()[0]; outch_id++)
            {
                for (size_t x_id = 0; x_id <= input.shape()[2] - kernel.shape()[2]; x_id++)
                {
                    for (size_t y_id = 0; y_id <= input.shape()[3] - kernel.shape()[3]; y_id++)
                    {
                        ACC tmp = convert_data<float, ACC>(0.0f);
                        // Do computation of kernel matrices over input matrices
                        for (size_t kx_id = 0; kx_id < kernel.shape()[2]; kx_id++)
                        {
                            for (size_t ky_id = 0; ky_id < kernel.shape()[3]; ky_id++)
                            {
                                tmp += convert_data<T, ACC>(input[{batch_id, inch_id, x_id + kx_id, y_id + ky_id}]) * convert_data<T, ACC>(kernel[{outch_id, inch_id, kx_id, ky_id}]);
                            }
                        }

                        t[{batch_id, outch_id, x_id, y_id}] += tmp;
                    }
                }
            }
        }
        // Quantize result with new factor and add new bias
        for (size_t x_id = 0; x_id < output_buffer.shape()[2]; x_id++)
        {
            for (size_t y_id = 0; y_id < output_buffer.shape()[3]; y_id++)
            {
                for (size_t outch_id = 0; outch_id < output_buffer.shape()[1]; outch_id++)
                {
                    ACC res = (relu_ACC(t[{batch_id, outch_id, x_id, y_id}] >> s_x_shift) + (convert_data<T, ACC>(bias[outch_id]) >> s_b_shift));

                    // Addition of Bias and Activation (ReLU)
                    output_buffer[{batch_id, outch_id, x_id, y_id}] = convert_data<ACC, T>(res);
                }
            }
        }
    }

    return output_buffer;
}

template<typename T, typename ACC>
const char* QuantConvolution<T, ACC>::name() const {
    return "QuantConvolution";
}

template<typename T, typename ACC>
LayerType QuantConvolution<T, ACC>::type() const {
    return LayerType::QuantConvolution;
}

template<typename T, typename ACC>
unsigned QuantConvolution<T, ACC>::serialize(ostream& stream) const {
    unsigned bytes = 0; 

    bytes += kernel.serialize(stream);
    bytes += bias.serialize(stream);

    bytes += serialize_number(s_b, stream);
    bytes += serialize_number(s_x, stream);
    bytes += serialize_number(s_w, stream);
    bytes += serialize_number(s_y, stream);
    bytes += serialize_vector(output_buffer.shape(), stream);

    return bytes;
}

template<typename T, typename ACC>
QuantConvolution<T, ACC> QuantConvolution<T, ACC>::deserialize(span<char>& data) {
    Matrix<T> kernel = Matrix<T>::deserialize(data);
    Matrix<T> bias = Matrix<T>::deserialize(data);

    float s_b = deserialize_number<float>(data);
    float s_x = deserialize_number<float>(data);
    float s_w = deserialize_number<float>(data);
    float s_y = deserialize_number<float>(data);

    vector<size_t> out_shape = deserialize_vector<size_t>(data);
    Matrix<T> output_buffer(out_shape);

    return QuantConvolution(kernel, bias, out_shape, s_b, s_x, s_w, s_y);
}
