/**
 * Copyright (c) 2026 Huawei Technologies Co., Ltd.
 * This program is free software, you can redistribute it and/or modify it under the terms and conditions of
 * CANN Open Software License Agreement Version 2.0 (the "License").
 * Please refer to the License for details. You may not use this file except in compliance with the License.
 * THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND, EITHER EXPRESS OR IMPLIED,
 * INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY, OR FITNESS FOR A PARTICULAR PURPOSE.
 * See LICENSE in the root of the software repository for the full text of the License.
 */

/*!
 * \file block_mmad_mx_full_load_A.h
 * \brief
 */

#ifndef MATMUL_BLOCK_MMAD_MX_QUANT_FULL_LOAD_A_H
#define MATMUL_BLOCK_MMAD_MX_QUANT_FULL_LOAD_A_H
#include "../utils/layout_utils.h"
#include "../utils/common_utils.h"
#include "../utils/quant_batch_matmul_constant.h"
#include "../utils/tuple_utils.h"
#include "../policy/dispatch_policy.h"
#include "include/experimental/tensor_api/tensor.h"
#include "../tile/tile_mmad_mx.h"
#include "../tile/copy_scale_l1_to_l0a.h"
#include "../tile/copy_scale_l1_to_l0b.h"
#include "../tile/copy_scale_gm_to_l1.h"
#include "../tile/pad_mx_kl1.h"

namespace Cmct {
namespace Gemm {
namespace Block {
using namespace AscendC;
using namespace AscendC::Te;
using namespace Cmct::Gemm::QuantBatchMatmul;

template <
    class DispatchPolicy_, class L1TileShape_, class L0TileShape_, class AType_, class LayoutA_, class BType_,
    class LayoutB_, class CType_, class LayoutC_, class BiasType_, class LayoutBias_, class TileCopy_,
    class Enable = void>
class BlockMmadMxFullLoad {
    static_assert(AscendC::Std::always_false_v<DispatchPolicy_>, "Should not be here!");
};

template <
    class DispatchPolicy_, class L1TileShape_, class L0TileShape_, class AType_, class LayoutA_, class BType_,
    class LayoutB_, class CType_, class LayoutC_, class BiasType_, class LayoutBias_, class TileCopy_>
class BlockMmadMxFullLoad<
    DispatchPolicy_, L1TileShape_, L0TileShape_, AType_, LayoutA_, BType_, LayoutB_, CType_, LayoutC_, BiasType_,
    LayoutBias_, TileCopy_,
    AscendC::Std::enable_if_t<
        AscendC::Std::is_base_of_v<MatmulWithScale<>, DispatchPolicy_> ||
        AscendC::Std::is_base_of_v<
            MatmulWithScale<AscendC::Shape<_0, _0, _0, _0>, A_FULL_LOAD_MODE>, DispatchPolicy_>>> {
public:
    using AType = AType_;
    using BType = BType_;
    using CType = CType_;
    using LayoutA = LayoutA_;
    using LayoutB = LayoutB_;
    using LayoutC = LayoutC_;
    using L1TileShape = L1TileShape_;
    using L0TileShape = L0TileShape_;
    using MxL0AType = typename GetL0DataType<AType, true>::Type;
    using MxL0BType = typename GetL0DataType<BType, true>::Type;
    using BiasType = BiasType_;
    using DispatchPolicy = DispatchPolicy_;
    using TupleShape = AscendC::Shape<int64_t, int64_t, int64_t>;
    using BlockShape = AscendC::Shape<int64_t, int64_t, int64_t, int64_t>;
    uint64_t m_;
    uint64_t n_;
    uint64_t k_;
    uint64_t l1BufNum_{1};
    uint64_t kL1Iter_{0};
    uint64_t kL1_{1};
    uint64_t scaleKL1_{1};
    uint64_t baseM_{16};
    uint64_t baseN_{16};
    uint64_t baseK_{16};
    bool isBias_{false};
    static constexpr CubeFormat formatB = TagToFormat<LayoutB>::format;
    static constexpr bool transA = TagToTrans<LayoutA>::value;
    static constexpr bool transB = TagToTrans<LayoutB>::value;
    // u8 element
    constexpr static uint64_t HALF_L0_SIZE = L0A_SIZE / DOUBLE_BUFFER_COUNT / sizeof(AType);
    constexpr static uint64_t HALF_L0C_SIZE = AscendC::TOTAL_L0C_SIZE / DOUBLE_BUFFER_COUNT / sizeof(float);
    constexpr static int32_t C0_SIZE = AscendC::AuxGetC0Size<AType>();
    constexpr static int32_t BIAS_C0 = AscendC::AuxGetC0Size<BiasType>();
    constexpr static uint64_t BLOCK_CUBE = 16UL;
    constexpr static uint64_t BLOCK_REDUCE_CUBE = 32UL;
    constexpr static uint64_t MXFP_GROUP_SIZE = 32UL;
    constexpr static uint64_t MXFP_DIVISOR_SIZE = 64UL;
    constexpr static uint64_t MXFP_MULTI_BASE_SIZE = 2;
    constexpr static uint64_t SCALE_BUFFER_NUM = 2;
    // Set unitflag state: 3 = final accumulation, 2 = non-final accumulation
    constexpr static uint32_t FINAL_ACCUMULATION = 3;
    constexpr static uint32_t NON_FINAL_ACCUMULATION = 2;

    using MakeLayoutAL1 =
        AscendC::Std::conditional_t<transA, AscendC::Te::ZnLayoutFormat<AType>, AscendC::Te::NzLayoutFormat<AType>>;
    using MakeLayoutBL1 =
        AscendC::Std::conditional_t<transB, AscendC::Te::ZnLayoutFormat<BType>, AscendC::Te::NzLayoutFormat<BType>>;

    uint64_t abL1LoopCnt_{0};
    uint64_t scaleLoopCnt_{0};
    uint64_t l0PingPong_{0};
    uint64_t l0cPingPong_{0};
    bool enableL0cPingPong_{false};

    struct TileL1L0Param {
        int64_t curM = 0;
        int64_t curN = 0;
        int64_t curGmAKL1 = 0;
        int64_t curGmBKL1 = 0;
        int64_t curPadAKL1 = 0; // pad to 64 align
        int64_t curPadBKL1 = 0; // pad to 64 align
    };

    struct Params {
        GM_ADDR aGmAddr{nullptr};
        GM_ADDR bGmAddr{nullptr};
        GM_ADDR cGmAddr{nullptr};
        GM_ADDR biasGmAddr{nullptr};
        GM_ADDR pertokenScaleGmAddr{nullptr};
        GM_ADDR scaleGmAddr{nullptr};
    };

    struct L1Params {
        uint64_t kL1;
        uint64_t scaleKL1;
        uint64_t l1BufNum;
    };

    __aicore__ inline BlockMmadMxFullLoad()
    {
        AscendC::SetFlag<AscendC::HardEvent::MTE1_MTE2>(INPUT_BUFFER_FLAG_0);
        AscendC::SetFlag<AscendC::HardEvent::MTE1_MTE2>(INPUT_BUFFER_FLAG_1);
        AscendC::SetFlag<AscendC::HardEvent::MTE1_MTE2>(INPUT_BUFFER_FLAG_2);
        AscendC::SetFlag<AscendC::HardEvent::MTE1_MTE2>(INPUT_BUFFER_FLAG_3);
        AscendC::SetFlag<AscendC::HardEvent::MTE1_MTE2>(SCALE_BUFFER_FLAG_0);
        AscendC::SetFlag<AscendC::HardEvent::MTE1_MTE2>(SCALE_BUFFER_FLAG_1);
        AscendC::SetFlag<AscendC::HardEvent::FIX_M>(INPUT_BUFFER_FLAG_0);
        AscendC::SetFlag<AscendC::HardEvent::FIX_M>(INPUT_BUFFER_FLAG_1);
        AscendC::SetMMLayoutTransform(true); // true means column first when fixpipe_l0c2out
    }

    __aicore__ inline ~BlockMmadMxFullLoad()
    {
        AscendC::WaitFlag<AscendC::HardEvent::MTE1_MTE2>(INPUT_BUFFER_FLAG_0);
        AscendC::WaitFlag<AscendC::HardEvent::MTE1_MTE2>(INPUT_BUFFER_FLAG_1);
        AscendC::WaitFlag<AscendC::HardEvent::MTE1_MTE2>(INPUT_BUFFER_FLAG_2);
        AscendC::WaitFlag<AscendC::HardEvent::MTE1_MTE2>(INPUT_BUFFER_FLAG_3);
        AscendC::WaitFlag<AscendC::HardEvent::MTE1_MTE2>(SCALE_BUFFER_FLAG_0);
        AscendC::WaitFlag<AscendC::HardEvent::MTE1_MTE2>(SCALE_BUFFER_FLAG_1);
        AscendC::WaitFlag<AscendC::HardEvent::FIX_M>(INPUT_BUFFER_FLAG_0);
        AscendC::WaitFlag<AscendC::HardEvent::FIX_M>(INPUT_BUFFER_FLAG_1);
        AscendC::SetMMLayoutTransform(false); // false means row first when fixpipe_l0c2out
    }

public:
    __aicore__ inline void Init(
        const TupleShape& problemShape, const BlockShape& l0TileShape, const L1Params& l1Params, bool isBias,
        bool dbL0C)
    {
        m_ = Get<IDX_M_IDX>(problemShape);
        n_ = Get<IDX_N_IDX>(problemShape);
        k_ = Get<IDX_K_IDX>(problemShape);
        kL1_ = l1Params.kL1;
        scaleKL1_ = l1Params.scaleKL1;
        baseM_ = Get<IDX_M_IDX>(l0TileShape);
        baseN_ = Get<IDX_N_IDX>(l0TileShape);
        baseK_ = Get<IDX_K_IDX>(l0TileShape);
        isBias_ = isBias;
        l1BufNum_ = l1Params.l1BufNum;
        enableL0cPingPong_ = dbL0C;
        constexpr bool isFp4Type = AscendC::IsSameType<AType, fp4x2_e2m1_t>::value;
        constexpr uint64_t sizeShift = isFp4Type ? 1 : 0;
        bL1OneBuffer_ = (baseN_ * kL1_) >> sizeShift;
        scaleBL1OneBuffer_ = baseN_ * Cmct::Gemm::CeilDiv(scaleKL1_, MXFP_DIVISOR_SIZE) * MXFP_MULTI_BASE_SIZE;
        if (isBias_) {
            biasL1OneBuffer_ = baseN_ * sizeof(BiasType);
        }
        uint64_t mAlign = Cmct::Gemm::Align(baseM_, transA ? C0_SIZE : BLOCK_CUBE);
        uint64_t kAlign = Cmct::Gemm::Align(k_, MXFP_DIVISOR_SIZE);
        aL1OneBuffer_ = (mAlign * kAlign) >> sizeShift;
        scaleAL1OneBuffer_ = baseM_ * Cmct::Gemm::CeilDiv(k_, MXFP_DIVISOR_SIZE) * MXFP_MULTI_BASE_SIZE;
        // 2 buffer: L1 space is : B0|BScale0|bias0|A|AScale|...|B1|BScale1|bias1|
        // 4 buffer: L1 space is : B0B2|BScale0|bias0|A|AScale|...|B1B3|BScale1|bias1|...
        l1BufferAOffset_[0] = bL1OneBuffer_ * (l1BufNum_ >> 1) + scaleBL1OneBuffer_ + biasL1OneBuffer_;
        l1BufferScaleAOffset_[0] = l1BufferAOffset_[0] + aL1OneBuffer_;
        uint64_t b1Offset = l1BufferScaleAOffset_[0] + scaleAL1OneBuffer_ >= (AscendC::TOTAL_L1_SIZE >> 1) ?
                                l1BufferScaleAOffset_[0] + scaleAL1OneBuffer_ :
                                (AscendC::TOTAL_L1_SIZE >> 1);
        for (int32_t bufferId = 0; bufferId < l1BufNum_; bufferId++) {
            l1BufferBOffset_[bufferId] = b1Offset * (bufferId & 1) + bL1OneBuffer_ * (bufferId >> 1);
        }
        for (int32_t bufferId = 0; bufferId < SCALE_BUFFER_NUM; bufferId++) {
            l1BufferScaleBOffset_[bufferId] = l1BufferBOffset_[bufferId] + bL1OneBuffer_ * (l1BufNum_ >> 1);
            l1BufferBiasOffset_[bufferId] = l1BufferScaleBOffset_[bufferId] + scaleBL1OneBuffer_;
        }
        kL1Iter_ = CeilDiv(k_, kL1_);
    }

    template <
        typename TensorA, typename TensorB, typename TensorScaleA, typename TensorScaleB, typename TensorBias,
        typename TensorC>
    __aicore__ inline void operator()(
        TensorA const& gmA, TensorB const& gmB, TensorScaleA const& gmScaleA, TensorScaleB const& gmScaleB,
        TensorBias const& gmBias, TensorC const& gmC, BlockShape const& singleShape)
    {
        TileL1L0Param tileL1L0Param;
        tileL1L0Param.curM = Get<IDX_M_TILEIDX>(singleShape);
        tileL1L0Param.curN = Get<IDX_N_TILEIDX>(singleShape);
        uint64_t l0cOffset = (l0cPingPong_ & 1) * HALF_L0C_SIZE;
        auto layoutL0C = AscendC::Te::MakeL0CLayout(tileL1L0Param.curM, tileL1L0Param.curN);
        tensorL0C = AscendC::Te::MakeTensor(AscendC::Te::MakeL0CmemPtr<float>(l0cOffset), layoutL0C);
        for (uint64_t iter0 = 0; iter0 < kL1Iter_; ++iter0) {
            uint64_t l1BufId = abL1LoopCnt_ & (l1BufNum_ - 1);
            uint64_t scaleL1BufId = scaleLoopCnt_ & 1;
            AscendC::WaitFlag<AscendC::HardEvent::MTE1_MTE2>(l1BufId);
            biasBufId_ = abL1LoopCnt_ & 1;
            tileL1L0Param.curGmBKL1 = (iter0 + 1 == kL1Iter_) ? (k_ - iter0 * kL1_) : kL1_;
            tileL1L0Param.curPadBKL1 =
                Cmct::Gemm::CeilAlign(tileL1L0Param.curGmBKL1, MXFP_DIVISOR_SIZE); // pad to 64 align
            tileL1L0Param.curGmAKL1 = tileL1L0Param.curGmBKL1;
            tileL1L0Param.curPadAKL1 = tileL1L0Param.curPadBKL1;

            // A, B GM->L1; 先slice再copy
            auto copyGM2L1 = AscendC::Te::MakeCopy(AscendC::Te::CopyGM2L1{});
            if (abL1LoopCnt_ < kL1Iter_) {
                auto layoutAL1 = MakeLayoutAL1{}(tileL1L0Param.curM, k_);
                auto gmBlockA =
                    gmA(AscendC::Te::MakeCoord(0, iter0 * kL1_),
                        AscendC::Te::MakeShape(tileL1L0Param.curM, tileL1L0Param.curGmAKL1));
                auto tensorTotalAL1 =
                    AscendC::Te::MakeTensor(AscendC::Te::MakeL1memPtr<AType>(l1BufferAOffset_[0]), layoutAL1);
                tensorAL1 = tensorTotalAL1(
                    AscendC::Te::MakeCoord(0, iter0 * kL1_),
                    AscendC::Te::MakeShape(tileL1L0Param.curM, tileL1L0Param.curPadAKL1));
                Cmct::Gemm::Tile::PadMxKAL1::PadZero(tensorAL1, gmBlockA);
                AscendC::Te::Copy(copyGM2L1, tensorAL1, gmBlockA);
            }

            auto layoutBL1 = MakeLayoutBL1{}(tileL1L0Param.curPadBKL1, tileL1L0Param.curN);
            tensorBL1 = AscendC::Te::MakeTensor(AscendC::Te::MakeL1memPtr<BType>(l1BufferBOffset_[l1BufId]), layoutBL1);
            auto gmBlockB =
                gmB(AscendC::Te::MakeCoord(iter0 * kL1_, 0),
                    AscendC::Te::MakeShape(tileL1L0Param.curGmBKL1, tileL1L0Param.curN));
            Cmct::Gemm::Tile::PadMxKBL1::PadZero(tensorBL1, gmBlockB);
            AscendC::Te::Copy(copyGM2L1, tensorBL1, gmBlockB);

            // scaleA, scaleB GM->L1
            uint64_t kL1Offset = iter0 * kL1_;
            auto CopyScaleGM2L1 = AscendC::Te::MakeCopy(Cmct::Gemm::Tile::CopyScaleGM2L1{});
            if (iter0 % (scaleKL1_ / kL1_) == 0) {
                AscendC::WaitFlag<AscendC::HardEvent::MTE1_MTE2>(SCALE_BUFFER_FLAG_0 + (scaleL1BufId));
                uint64_t curScaleKL1 = scaleKL1_;
                if (kL1Offset + curScaleKL1 > k_) {
                    curScaleKL1 = k_ - kL1Offset;
                }
                auto layoutScaleBL1 = AscendC::Te::MakeNnLayout<fp8_e8m0_t>(
                    Cmct::Gemm::CeilDiv(scaleKL1_, MXFP_DIVISOR_SIZE) * 2, tileL1L0Param.curN);
                tensorScaleBL1 = AscendC::Te::MakeTensor(
                    AscendC::Te::MakeL1memPtr<fp8_e8m0_t>(l1BufferScaleBOffset_[scaleL1BufId]), layoutScaleBL1);
                auto gmBlockScaleB = gmScaleB(
                    AscendC::Te::MakeCoord(iter0 * kL1_ / MXFP_GROUP_SIZE, 0),
                    AscendC::Te::MakeShape(
                        Cmct::Gemm::CeilDiv(curScaleKL1, MXFP_DIVISOR_SIZE) * MXFP_MULTI_BASE_SIZE,
                        tileL1L0Param.curN));
                AscendC::Te::Copy(CopyScaleGM2L1, tensorScaleBL1, gmBlockScaleB);
            }
            if (abL1LoopCnt_ == 0 && kL1Offset == 0) {
                auto layoutScaleAL1 = AscendC::Te::MakeZzLayout<fp8_e8m0_t>(
                    tileL1L0Param.curM, Cmct::Gemm::CeilDiv(k_, MXFP_DIVISOR_SIZE) * 2);
                tensorScaleAL1 = AscendC::Te::MakeTensor(
                    AscendC::Te::MakeL1memPtr<fp8_e8m0_t>(l1BufferScaleAOffset_[0]), layoutScaleAL1);
                AscendC::Te::Copy(CopyScaleGM2L1, tensorScaleAL1, gmScaleA);
            }

            // bias GM->L1
            if (isBias_ && iter0 == 0) {
                auto layoutBiasL1 =
                    AscendC::Te::MakeNDLayout<BiasType>(1L, Cmct::Gemm::Align(tileL1L0Param.curN, AscendC::BLOCK_CUBE));
                tensorBiasL1 = AscendC::Te::MakeTensor(
                    AscendC::Te::MakeL1memPtr<BiasType>(l1BufferBiasOffset_[biasBufId_]), layoutBiasL1);
                AscendC::Te::Copy(copyGM2L1, tensorBiasL1, gmBias);
            }

            AscendC::SetFlag<AscendC::HardEvent::MTE2_MTE1>(l1BufId);
            AscendC::WaitFlag<AscendC::HardEvent::MTE2_MTE1>(l1BufId);

            Iterate(tileL1L0Param, iter0);

            AscendC::SetFlag<AscendC::HardEvent::MTE1_MTE2>(l1BufId);
            if ((iter0 + 1) % (scaleKL1_ / kL1_) == 0 || iter0 == kL1Iter_ - 1) {
                AscendC::SetFlag<AscendC::HardEvent::MTE1_MTE2>(SCALE_BUFFER_FLAG_0 + (scaleL1BufId));
                scaleLoopCnt_++;
            }
            abL1LoopCnt_++;
        }
        // C L0C->GM
        auto CopyL0C2GM = AscendC::Te::MakeCopy(AscendC::Te::CopyL0C2GM{});
        AscendC::Te::Copy(CopyL0C2GM, gmC, tensorL0C, AscendC::Te::FixpipeParams{3});
        if (enableL0cPingPong_) {
            l0cPingPong_++;
        }
    }

    __aicore__ inline void Iterate(TileL1L0Param& tileL1L0Param, uint64_t iter0)
    {
        // 从scaleKL1中切出kL1_对应的部分
        auto coordScaleKL1 = iter0 * Cmct::Gemm::CeilDiv(kL1_, MXFP_DIVISOR_SIZE) * 2;
        auto tensorBlockScaleAL1 = tensorScaleAL1(
            AscendC::Te::MakeCoord(0, coordScaleKL1),
            AscendC::Te::MakeShape(tileL1L0Param.curM, Cmct::Gemm::CeilDiv(kL1_, MXFP_DIVISOR_SIZE) * 2));
        coordScaleKL1 = (iter0 % (scaleKL1_ / kL1_)) * Cmct::Gemm::CeilDiv(kL1_, MXFP_DIVISOR_SIZE) * 2;
        auto tensorBlockScaleBL1 = tensorScaleBL1(
            AscendC::Te::MakeCoord(coordScaleKL1, 0),
            AscendC::Te::MakeShape(Cmct::Gemm::CeilDiv(kL1_, MXFP_DIVISOR_SIZE) * 2, tileL1L0Param.curN));

        int64_t kL0Iter = Cmct::Gemm::CeilDiv(tileL1L0Param.curGmBKL1, static_cast<int64_t>(baseK_));
        for (uint16_t iter1 = 0; iter1 < kL0Iter; ++iter1) {
            auto curKL0 = (iter1 * baseK_ + baseK_ > tileL1L0Param.curPadBKL1) ?
                              (tileL1L0Param.curPadBKL1 - iter1 * baseK_) :
                              baseK_;
            // Load data to L0 and open DB(unit: B8)
            uint64_t l0Offset = HALF_L0_SIZE * (l0PingPong_ & 0x1);
            AscendC::WaitFlag<AscendC::HardEvent::M_MTE1>(l0PingPong_ & 0x1);

            // A, B L1->L0
            auto CopyL12L0 = AscendC::Te::MakeCopy(AscendC::Te::CopyL12L0{});
            auto layoutAL0 = AscendC::Te::MakeNzLayout<AType>(tileL1L0Param.curM, curKL0);
            auto tensorAL0 = AscendC::Te::MakeTensor(AscendC::Te::MakeL0AmemPtr<AType>(l0Offset), layoutAL0);
            auto tensorBlockAL1 = tensorAL1(
                AscendC::Te::MakeCoord(0, iter1 * baseK_), AscendC::Te::MakeShape(tileL1L0Param.curM, curKL0));
            AscendC::Te::Copy(CopyL12L0, tensorAL0, tensorBlockAL1);

            auto layoutBL0 = AscendC::Te::MakeZnLayout<BType>(curKL0, tileL1L0Param.curN);
            auto tensorBL0 = AscendC::Te::MakeTensor(AscendC::Te::MakeL0BmemPtr<BType>(l0Offset), layoutBL0);
            auto tensorBlockBL1 = tensorBL1(
                AscendC::Te::MakeCoord(iter1 * baseK_, 0), AscendC::Te::MakeShape(curKL0, tileL1L0Param.curN));
            AscendC::Te::Copy(CopyL12L0, tensorBL0, tensorBlockBL1);

            // scaleA, scaleB L1->L0
            auto layoutScaleAL0 = AscendC::Te::MakeZzLayout<fp8_e8m0_t>(
                tileL1L0Param.curM, Cmct::Gemm::CeilDiv(curKL0, MXFP_DIVISOR_SIZE) * 2);
            auto tensorScaleAL0 =
                AscendC::Te::MakeTensor(AscendC::Te::MakeL0AmemPtr<fp8_e8m0_t>(l0Offset), layoutScaleAL0);
            auto CopyL12L0MxScaleA3510 = AscendC::Te::MakeCopy(Cmct::Gemm::Tile::CopyL12L0MxScaleA3510{});
            AscendC::Te::Copy(
                CopyL12L0MxScaleA3510, tensorScaleAL0, tensorBlockScaleAL1,
                AscendC::Te::MakeCoord(0, iter1 * Cmct::Gemm::CeilDiv(baseK_, MXFP_DIVISOR_SIZE) * 2));

            auto layoutScaleBL0 = AscendC::Te::MakeNnLayout<fp8_e8m0_t>(
                Cmct::Gemm::CeilDiv(curKL0, MXFP_DIVISOR_SIZE) * 2, tileL1L0Param.curN);
            auto tensorScaleBL0 =
                AscendC::Te::MakeTensor(AscendC::Te::MakeL0BmemPtr<fp8_e8m0_t>(l0Offset), layoutScaleBL0);
            auto CopyL12L0MxScaleB3510 = AscendC::Te::MakeCopy(Cmct::Gemm::Tile::CopyL12L0MxScaleB3510{});
            AscendC::Te::Copy(
                CopyL12L0MxScaleB3510, tensorScaleBL0, tensorBlockScaleBL1,
                AscendC::Te::MakeCoord(iter1 * Cmct::Gemm::CeilDiv(baseK_, MXFP_DIVISOR_SIZE) * 2, 0));

            // bias L1->BT
            auto layoutBt =
                AscendC::Te::MakeNDLayout<float>(1L, Cmct::Gemm::Align(tileL1L0Param.curN, AscendC::BLOCK_CUBE));
            auto tensorBt = AscendC::Te::MakeTensor(
                AscendC::Te::MakeBiasmemPtr<float>(baseN_ * biasBufId_ * sizeof(float)), layoutBt);
            if (NeedBias(iter0, iter1)) {
                auto CopyL12BT = AscendC::Te::MakeCopy(AscendC::Te::CopyL12BT{});
                AscendC::Te::Copy(CopyL12BT, tensorBt, tensorBiasL1);
            }

            AscendC::SetFlag<AscendC::HardEvent::MTE1_M>(l0PingPong_ & 0x1);
            AscendC::WaitFlag<AscendC::HardEvent::MTE1_M>(l0PingPong_ & 0x1);
            // mmad_mx
            uint8_t mmadUnitFlag =
                (iter0 + 1 == kL1Iter_ && iter1 + 1 == kL0Iter) ? FINAL_ACCUMULATION : NON_FINAL_ACCUMULATION;
            bool mmadCmatrixInitVal = (iter0 == 0 && iter1 == 0 && !isBias_);
            if (NeedBias(iter0, iter1)) {
                AscendC::Te::Mad(
                    AscendC::Te::MmadAtom<AscendC::Te::MmadTraits<Tile::MmadMxWithBias>>{}.with(
                        static_cast<uint16_t>(tileL1L0Param.curM),
                        static_cast<uint16_t>(Cmct::Gemm::CeilAlign(curKL0, MXFP_DIVISOR_SIZE)),
                        static_cast<uint16_t>(tileL1L0Param.curN), mmadUnitFlag, true, mmadCmatrixInitVal),
                    tensorL0C, tensorAL0, tensorBL0, tensorBt);
            } else {
                AscendC::Te::Mad(
                    AscendC::Te::MmadAtom<AscendC::Te::MmadTraits<Tile::MmadMx>>{}.with(
                        static_cast<uint16_t>(tileL1L0Param.curM),
                        static_cast<uint16_t>(Cmct::Gemm::CeilAlign(curKL0, MXFP_DIVISOR_SIZE)),
                        static_cast<uint16_t>(tileL1L0Param.curN), mmadUnitFlag, false, mmadCmatrixInitVal),
                    tensorL0C, tensorAL0, tensorBL0);
            }
            AscendC::SetFlag<AscendC::HardEvent::M_MTE1>(l0PingPong_ & 0x1);
            l0PingPong_++;
        }
    }

private:
    __aicore__ inline bool NeedBias(uint64_t kIter0, uint64_t kIter1)
    {
        return isBias_ && kIter0 == 0 && kIter1 == 0;
    }

    constexpr static uint16_t SCALE_BUFFER_FLAG_0 = 4;
    constexpr static uint16_t SCALE_BUFFER_FLAG_1 = 5;
    uint16_t biasBufId_ = 0;
    uint64_t biasL1OneBuffer_ = 0UL;
    uint64_t aL1OneBuffer_ = 0UL;
    uint64_t bL1OneBuffer_ = 0UL;
    uint64_t scaleAL1OneBuffer_ = 0UL;
    uint64_t scaleBL1OneBuffer_ = 0UL;
    uint64_t l1BufferAOffset_[4] = {0UL};      // default 4 buffer
    uint64_t l1BufferBOffset_[4] = {0UL};      // default 4 buffer
    uint64_t l1BufferScaleAOffset_[2] = {0UL}; // default 2 buffer
    uint64_t l1BufferScaleBOffset_[2] = {0UL}; // default 2 buffer
    uint64_t l1BufferBiasOffset_[2] = {0UL};   // default 2 buffer
    using TensorAL1 = decltype(AscendC::Te::MakeTensor(AscendC::Te::MakeL1memPtr<AType>(0), MakeLayoutAL1{}(0L, 0L)));
    TensorAL1 tensorAL1;
    using TensorScaleAL1 = decltype(AscendC::Te::MakeTensor(
        AscendC::Te::MakeL1memPtr<fp8_e8m0_t>(0), AscendC::Te::MakeZzLayout<fp8_e8m0_t>(0L, 0L)));
    TensorScaleAL1 tensorScaleAL1;
    using TensorBL1 = decltype(AscendC::Te::MakeTensor(AscendC::Te::MakeL1memPtr<BType>(0), MakeLayoutBL1{}(0L, 0L)));
    TensorBL1 tensorBL1;
    using TensorScaleBL1 = decltype(AscendC::Te::MakeTensor(
        AscendC::Te::MakeL1memPtr<fp8_e8m0_t>(0), AscendC::Te::MakeNnLayout<fp8_e8m0_t>(0L, 0L)));
    TensorScaleBL1 tensorScaleBL1;
    using TensorBiasL1 = decltype(AscendC::Te::MakeTensor(
        AscendC::Te::MakeL1memPtr<BiasType>(0), AscendC::Te::MakeNDLayout<BiasType>(1L, 0L)));
    TensorBiasL1 tensorBiasL1;
    using TensorL0C =
        decltype(AscendC::Te::MakeTensor(AscendC::Te::MakeL0CmemPtr<float>(0), AscendC::Te::MakeL0CLayout(0L, 0L)));
    TensorL0C tensorL0C;
};
} // namespace Block
} // namespace Gemm
} // namespace Cmct

#endif
