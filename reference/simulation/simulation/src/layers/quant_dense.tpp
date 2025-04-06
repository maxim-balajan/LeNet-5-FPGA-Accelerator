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
#include "quant_dense.h"
#include "../data/data_converter.h"

#include <cmath>
#include <limits>

template<typename T, typename ACC>
QuantDense<T, ACC>::QuantDense(Matrix<T> weights, Matrix<T> bias, bool enable_softmax, Matrix<T> output_buffer, float s_b, float s_x, float s_w, float s_y)
    : weights(weights)
    , bias(bias)
    , enable_softmax(enable_softmax)
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
QuantDense<T, ACC>::QuantDense(Matrix<T> weights, Matrix<T> bias, bool enable_softmax, size_t batching, size_t x, float s_b, float s_x, float s_w, float s_y)
    : QuantDense(weights, bias, enable_softmax, Matrix<T>({batching, x}), s_b, s_x, s_w, s_y) {}


template<typename T, typename ACC>
const Matrix<T>& QuantDense<T, ACC>::calc(const Matrix<T>& input)
{
    for (size_t batch_id = 0; batch_id < input.shape()[0]; batch_id++)
    {
        for (size_t wy_id = 0; wy_id < weights.shape()[1]; wy_id++)
        {
            ACC tmp = convert_data<float, ACC>(0.0f);

            for (size_t x_id = 0; x_id < input.shape()[1]; x_id++)
            {
                tmp += convert_data<T, ACC>(weights[{x_id, wy_id}]) * convert_data<T, ACC>(input[{batch_id, x_id}]);
            }

            ACC res = (tmp >> s_x_shift) + (convert_data<T, ACC>(bias[{wy_id}]) >> s_b_shift);
            output_buffer[{batch_id, wy_id}] = convert_data<ACC, T>(res);
        }
    }

    if (enable_softmax) {
        softmax(output_buffer);
    }

    return output_buffer;
}

template<typename T, typename ACC>
const char* QuantDense<T, ACC>::name() const {
    return "QuantDense";
}

template<typename T, typename ACC>
LayerType QuantDense<T, ACC>::type() const {
    return LayerType::QuantDense;
}

template<typename T, typename ACC>
unsigned QuantDense<T, ACC>::serialize(ostream& stream) const {
    unsigned bytes = 0; 

    bytes += weights.serialize(stream);
    bytes += bias.serialize(stream);

    bytes += serialize_number(s_b, stream);
    bytes += serialize_number(s_x, stream);
    bytes += serialize_number(s_w, stream);
    bytes += serialize_number(s_y, stream);
    bytes += serialize_number(static_cast<int>(enable_softmax), stream);
    bytes += serialize_vector(output_buffer.shape(), stream);

    return bytes;
}


template<typename T, typename ACC>
QuantDense<T, ACC> QuantDense<T, ACC>::deserialize(span<char>& data) {
    Matrix<T> weights = Matrix<T>::deserialize(data);
    Matrix<T> bias = Matrix<T>::deserialize(data);

    float s_b = deserialize_number<float>(data);
    float s_x = deserialize_number<float>(data);
    float s_w = deserialize_number<float>(data);
    float s_y = deserialize_number<float>(data);

    bool enable_softmax = deserialize_number<int>(data) != 0;

    vector<size_t> out_shape = deserialize_vector<size_t>(data);
    Matrix<T> output_buffer(out_shape);

    return QuantDense(weights, bias, enable_softmax, output_buffer, s_b, s_x, s_w, s_y);
}
