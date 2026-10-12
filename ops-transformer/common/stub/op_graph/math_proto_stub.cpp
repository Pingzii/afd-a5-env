/**
 * Copyright (c) 2026 Huawei Technologies Co., Ltd.
 * This program is free software; you can redistribute it and/or modify it under the terms and conditions of
 * CANN Open Software License Agreement Version 2.0 (the "License").
 * Please refer to the License for details. You may not use this file except in compliance with the License.
 * THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND, EITHER EXPRESS OR IMPLIED,
 * INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY, OR FITNESS FOR A PARTICULAR PURPOSE.
 * See LICENSE in the root of the software repository for the full text of the License.
 */

/* !
 * \file math_proto_stub.cpp
 * \brief
 */

#include "graph/operator_reg.h"
#include "register/op_impl_registry.h"

namespace ge {
/**
* @brief Permutes the dimensions according to perm.
         The returned tensor's dimension i will correspond to the input dimension perm[i].

* @par Inputs:
* Two inputs, including:
* @li x: A Tensor. Must be one of the following types:
* bfloat16, float16, float32, double, int64, int32, uint8, uint16, uint32, uint64, int8,
* int16, complex32, complex64, complex128, qint8, quint8, qint16, quint16, qint32, bool, hifloat8, float8_e5m2,
* float8_e4m3fn, and the maximum dimension should not exceed 8 dimensions,
* and the shape should be consistent with output.
* @li perm: A Tensor of type int32 or int64. A permutation of the dimensions of "x", the value
* should be within the range of [0, number of dimensions for self -1].

* @par Outputs:
* y: A Tensor. Has the same type as "x".

* @par Third-party framework compatibility
* Compatible with the TensorFlow operator Transpose.
*/
REG_OP(Transpose)
    .INPUT(x, TensorType({DT_BF16,      DT_FLOAT16,   DT_FLOAT,      DT_DOUBLE,   DT_INT64,       DT_INT32,
                          DT_UINT8,     DT_UINT16,    DT_UINT32,     DT_UINT64,   DT_INT8,        DT_INT16,
                          DT_COMPLEX32, DT_COMPLEX64, DT_COMPLEX128, DT_QINT8,    DT_QUINT8,      DT_QINT16,
                          DT_QUINT16,   DT_QINT32,    DT_BOOL,       DT_HIFLOAT8, DT_FLOAT8_E5M2, DT_FLOAT8_E4M3FN}))
    .INPUT(perm, TensorType::IndexNumberType())
    .OUTPUT(y, TensorType({DT_BF16,      DT_FLOAT16,   DT_FLOAT,      DT_DOUBLE,   DT_INT64,       DT_INT32,
                           DT_UINT8,     DT_UINT16,    DT_UINT32,     DT_UINT64,   DT_INT8,        DT_INT16,
                           DT_COMPLEX32, DT_COMPLEX64, DT_COMPLEX128, DT_QINT8,    DT_QUINT8,      DT_QINT16,
                           DT_QUINT16,   DT_QINT32,    DT_BOOL,       DT_HIFLOAT8, DT_FLOAT8_E5M2, DT_FLOAT8_E4M3FN}))
    .OP_END_FACTORY_REG(Transpose)

    /**
     *@brief This operation convert output dataType and shape.

     *@par Inputs:
     *The input handle must have the resource type. Inputs include:
     *x:A list of Tensor objects. One or more tensors from which
     the enqueued tensors should be taken . \n

     *@par Outputs:
     *y:A list of Tensor objects. One or more tensors from which
     the enqueued tensors should be taken . \n

     *@par Attributes:
     *type: An optional ge::DataType. It refers to the target data type of outputs . \n
     *keepdim: If True, output dims equal intput dims. otherwise output dims can append. default value is false.  \n

     *@par Third-party framework compatibility
     *Compatible with tensorflow QueueIsClosed operator.
     */
    REG_OP(Bitcast)
    .INPUT(x, TensorType({DT_BOOL,       DT_FLOAT16, DT_FLOAT,  DT_INT4,   DT_INT8,    DT_INT32,  DT_UINT32,
                          DT_UINT8,      DT_INT64,   DT_UINT64, DT_INT16,  DT_UINT16,  DT_DOUBLE, DT_COMPLEX64,
                          DT_COMPLEX128, DT_QINT8,   DT_QUINT8, DT_QINT16, DT_QUINT16, DT_QINT32}))
    .OUTPUT(y, TensorType({DT_BOOL,       DT_FLOAT16, DT_FLOAT,  DT_INT4,   DT_INT8,    DT_INT32,  DT_UINT32,
                           DT_UINT8,      DT_INT64,   DT_UINT64, DT_INT16,  DT_UINT16,  DT_DOUBLE, DT_COMPLEX64,
                           DT_COMPLEX128, DT_QINT8,   DT_QUINT8, DT_QINT16, DT_QUINT16, DT_QINT32}))
    .REQUIRED_ATTR(type, Type)
    .ATTR(keep_dim, Bool, false)
    .OP_END_FACTORY_REG(Bitcast)
} // namespace ge
