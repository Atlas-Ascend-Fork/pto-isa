/**
Copyright (c) 2025 Huawei Technologies Co., Ltd.
This program is free software, you can redistribute it and/or modify it under the terms and conditions of
CANN Open Software License Agreement Version 2.0 (the "License").
Please refer to the License for details. You may not use this file except in compliance with the License.
THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND, EITHER EXPRESS OR IMPLIED,
INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY, OR FITNESS FOR A PARTICULAR PURPOSE.
See LICENSE in the root of the software repository for the full text of the License.
*/

#include <pto/pto-inst.hpp>
#include <pto/common/constants.hpp>
#include "acl/acl.h"

using namespace pto;

template <typename T, int kTRows_, int kTCols_, int vRows, int vCols, bool highPrecision>
__global__ AICORE void runTRem(__gm__ T __out__* out, __gm__ T __in__* src0, __gm__ T __in__* src1)
{
    using DynShapeDim5 = Shape<1, 1, 1, vRows, vCols>;
    using DynStridDim5 = pto::Stride<1, 1, 1, vCols, 1>;
    using GlobalData = GlobalTensor<T, DynShapeDim5, DynStridDim5>;
    using TileData = Tile<TileType::Vec, T, kTRows_, kTCols_, BLayout::RowMajor, -1, -1>;
    TileData src0Tile(vRows, vCols);
    TileData src1Tile(vRows, vCols);
    TileData dstTile(vRows, vCols);
    TileData tmpTile(1, vCols);
    TASSIGN(src0Tile, 0x0);
    TASSIGN(src1Tile, kTRows_ * kTCols_ * sizeof(T));
    TASSIGN(dstTile, kTRows_ * kTCols_ * sizeof(T) * 2);
    TASSIGN(tmpTile, kTRows_ * kTCols_ * sizeof(T) * 3);
    constexpr auto precisionType = highPrecision ? RemAlgorithm::HIGH_PRECISION : RemAlgorithm::DEFAULT;

    GlobalData src0Global(src0);
    GlobalData src1Global(src1);
    GlobalData dstGlobal(out);

    Event<Op::TLOAD, Op::TREM> event0;
    Event<Op::TREM, Op::TSTORE_VEC> event1;

    TLOAD(src0Tile, src0Global);
    event0 = TLOAD(src1Tile, src1Global);
    event1 = TREM<precisionType>(dstTile, src0Tile, src1Tile, tmpTile, event0);
    TSTORE(dstGlobal, dstTile, event1);
    out = dstGlobal.data();
}

template <typename T, int kTRows_, int kTCols_, int vRows, int vCols, bool isHalf, bool highPrecision>
void LaunchTRem(T* out, T* src0, T* src1, void* stream)
{
    if constexpr (isHalf) {
        runTRem<half, kTRows_, kTCols_, vRows, vCols, highPrecision>
            <<<1, nullptr, stream>>>((half*)out, (half*)src0, (half*)src1);
    } else {
        runTRem<T, kTRows_, kTCols_, vRows, vCols, highPrecision><<<1, nullptr, stream>>>(out, src0, src1);
    }
}

template void LaunchTRem<uint16_t, 64, 64, 64, 64, false, false>(
    uint16_t* out, uint16_t* src0, uint16_t* src1, void* stream);
template void LaunchTRem<uint16_t, 64, 64, 63, 63, false, false>(
    uint16_t* out, uint16_t* src0, uint16_t* src1, void* stream);
template void LaunchTRem<uint16_t, 2048, 16, 2048, 16, false, false>(
    uint16_t* out, uint16_t* src0, uint16_t* src1, void* stream);
template void LaunchTRem<float, 32, 32, 32, 32, false, true>(float* out, float* src0, float* src1, void* stream);
template void LaunchTRem<uint32_t, 8, 8, 8, 8, false, false>(
    uint32_t* out, uint32_t* src0, uint32_t* src1, void* stream);
template void LaunchTRem<aclFloat16, 32, 32, 31, 31, true, false>(
    aclFloat16* out, aclFloat16* src0, aclFloat16* src1, void* stream);
template void LaunchTRem<int16_t, 16, 16, 16, 16, false, false>(
    int16_t* out, int16_t* src0, int16_t* src1, void* stream);
template void LaunchTRem<int32_t, 8, 8, 8, 8, false, false>(int32_t* out, int32_t* src0, int32_t* src1, void* stream);
template void LaunchTRem<float, 64, 64, 64, 64, false, true>(float* out, float* src0, float* src1, void* stream);
template void LaunchTRem<float, 128, 128, 96, 96, false, true>(float* out, float* src0, float* src1, void* stream);
template void LaunchTRem<float, 128, 128, 96, 97, false, true>(float* out, float* src0, float* src1, void* stream);
template void LaunchTRem<float, 1, 64, 1, 64, false, true>(float* out, float* src0, float* src1, void* stream);
template void LaunchTRem<float, 2, 64, 2, 64, false, true>(float* out, float* src0, float* src1, void* stream);
template void LaunchTRem<float, 4, 64, 4, 64, false, true>(float* out, float* src0, float* src1, void* stream);
template void LaunchTRem<float, 8, 64, 8, 64, false, true>(float* out, float* src0, float* src1, void* stream);
template void LaunchTRem<float, 1, 512, 1, 512, false, true>(float* out, float* src0, float* src1, void* stream);
template void LaunchTRem<float, 4, 128, 4, 65, false, true>(float* out, float* src0, float* src1, void* stream);
template void LaunchTRem<float, 16, 64, 16, 64, false, true>(float* out, float* src0, float* src1, void* stream);
template void LaunchTRem<float, 24, 64, 24, 64, false, true>(float* out, float* src0, float* src1, void* stream);
template void LaunchTRem<float, 32, 64, 32, 64, false, true>(float* out, float* src0, float* src1, void* stream);
template void LaunchTRem<float, 48, 64, 48, 64, false, true>(float* out, float* src0, float* src1, void* stream);
template void LaunchTRem<int64_t, 4, 16, 4, 16, false, false>(int64_t* out, int64_t* src0, int64_t* src1, void* stream);
template void LaunchTRem<uint64_t, 4, 16, 4, 16, false, false>(
    uint64_t* out, uint64_t* src0, uint64_t* src1, void* stream);
template void LaunchTRem<int64_t, 4, 64, 4, 64, false, false>(int64_t* out, int64_t* src0, int64_t* src1, void* stream);
template void LaunchTRem<uint64_t, 4, 64, 4, 64, false, false>(
    uint64_t* out, uint64_t* src0, uint64_t* src1, void* stream);
template void LaunchTRem<int64_t, 32, 32, 32, 32, false, false>(
    int64_t* out, int64_t* src0, int64_t* src1, void* stream);
template void LaunchTRem<uint64_t, 32, 32, 32, 32, false, false>(
    uint64_t* out, uint64_t* src0, uint64_t* src1, void* stream);

template <typename T, int tileH, int tileW, int vRows, int vCols, bool highPrecision>
__global__ AICORE void runTRemInplace(__gm__ T* out, __gm__ T* src1)
{
    using DynShapeDim5 = Shape<1, 1, 1, vRows, vCols>;
    using DynStridDim5 = pto::Stride<tileH * tileW, tileH * tileW, tileH * tileW, tileW, 1>;
    using GlobalData = GlobalTensor<T, DynShapeDim5, DynStridDim5>;
    using TileData = Tile<TileType::Vec, T, tileH, tileW, BLayout::RowMajor, -1, -1>;
    TileData src0Tile(vRows, vCols);
    TileData dstTile(vRows, vCols);
    TileData src1Tile(vRows, vCols);
    TileData tmpTile(1, vCols);
    constexpr unsigned tileBytes = tileH * tileW * sizeof(T);
    TASSIGN(src0Tile, 0x0);
    TASSIGN(dstTile, 0x0);
    TASSIGN(src1Tile, tileBytes);
    TASSIGN(tmpTile, tileBytes * 2);

    GlobalData src0Global((__gm__ T*)out);
    GlobalData dstGlobal(out);
    GlobalData src1Global(src1);

    TLOAD(src0Tile, src0Global);
    TLOAD(src1Tile, src1Global);
#ifndef __PTO_AUTO__
    set_flag(PIPE_MTE2, PIPE_V, EVENT_ID0);
    wait_flag(PIPE_MTE2, PIPE_V, EVENT_ID0);
#endif
    constexpr auto precisionType = highPrecision ? RemAlgorithm::HIGH_PRECISION : RemAlgorithm::DEFAULT;
    TREM<precisionType>(dstTile, src0Tile, src1Tile, tmpTile);
#ifndef __PTO_AUTO__
    set_flag(PIPE_V, PIPE_MTE3, EVENT_ID0);
    wait_flag(PIPE_V, PIPE_MTE3, EVENT_ID0);
#endif
    TSTORE(dstGlobal, dstTile);
    out = dstGlobal.data();
}

template <typename T, int tileH, int tileW, int vRows, int vCols, bool highPrecision>
void LaunchTRemInplace(T* out, T* src1, void* stream)
{
    runTRemInplace<T, tileH, tileW, vRows, vCols, highPrecision><<<1, nullptr, stream>>>(out, src1);
}

template void LaunchTRemInplace<int64_t, 4, 32, 4, 32, false>(int64_t* out, int64_t* src1, void* stream);
template void LaunchTRemInplace<uint64_t, 4, 32, 4, 32, false>(uint64_t* out, uint64_t* src1, void* stream);
template void LaunchTRemInplace<int64_t, 1, 1024, 1, 1024, false>(int64_t* out, int64_t* src1, void* stream);
template void LaunchTRemInplace<int64_t, 1, 2048, 1, 2045, false>(int64_t* out, int64_t* src1, void* stream);
template void LaunchTRemInplace<int64_t, 4, 64, 4, 40, false>(int64_t* out, int64_t* src1, void* stream);
template void LaunchTRemInplace<uint64_t, 4, 64, 4, 40, false>(uint64_t* out, uint64_t* src1, void* stream);
template void LaunchTRemInplace<float, 8, 64, 8, 64, true>(float* out, float* src1, void* stream);
