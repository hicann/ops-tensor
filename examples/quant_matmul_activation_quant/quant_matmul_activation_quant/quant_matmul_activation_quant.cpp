/**
 * Copyright (c) 2026 Huawei Technologies Co., Ltd.
 * This program is free software, you can redistribute it and/or modify it under the terms and conditions of
 * CANN Open Software License Agreement Version 2.0 (the "License").
 * Please refer to the License for details. You may not use this file except in compliance with the License.
 * THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND, EITHER EXPRESS OR IMPLIED,
 * INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY OR FITNESS FOR A PARTICULAR PURPOSE.
 * See LICENSE in the root of the software repository for the full text of the License.
 */

/**
 * @file quant_matmul_activation_quant.cpp
 * @brief CSV-driven MX quantized matmul + Gelu + dynamic MX quant fusion example.
 *
 * Exercises Blaze::Gemm::Kernel::GemmUniversal (kernel_qbmm_mx_activation_quant.h
 * specialization) with Blaze::Gemm::MatmulWithScaleMx dispatch policy and
 * Blaze::Epilogue::Block::BlockEpilogueGeluMxQuant epilogue.
 *
 * Both A and B are MX-quantized (FP8), each carrying an independent E8M0 scale.
 * AIC does MX GEMM (L0C→UB via DualDst fixpipe), AIV does Gelu activation and
 * dynamic MX quantization, outputting quantized Y (same dtype as A/C) + fp8_e8m0 scale.
 *
 * Supported transposes: transA (A stored as (K,M)), transB (B stored as (N,K))
 * Weight B is always in NZ layout (ZN when transB=true).
 *
 * Supported A dtypes: fp8_e4m3, fp8_e5m2, fp4_e2m1. B dtype: fp8_e4m3 or fp4_e2m1 (must match A's FP4/FP8 category).
 * C dtype (matmul intermediate / epilogue input): float32 (L0C accumulator, DualDst to UB).
 * Bias dtype: float32
 */

#ifndef K_MAX_SHAPE_DIM
#define K_MAX_SHAPE_DIM 0
#endif

#include <cstdint>
#include <cstdio>
#include <cstdlib>
#include <string>
#include <type_traits>
#include <vector>

#include "acl/acl.h"
#include "blaze/epilogue/block/block_epilogue_gelu_mx_quant.h"
#include "blaze/gemm/block/block_mmad_qbmm_mx.h"
#include "blaze/gemm/block/block_scheduler_qbmm.h"
#include "blaze/gemm/kernel/kernel_qbmm_mx_activation_quant.h"
#include "blaze/gemm/policy/dispatch_policy.h"
#include "data_utils.h"
#include "kernel_basic_intf.h"
#include "platform/platform_ascendc.h"

/* ========================================================================== */
/* Constants                                                                  */
/* ========================================================================== */

static constexpr uint64_t GROUP_SIZE = 32UL;
static constexpr uint64_t MXFP_DIVISOR_SIZE = 64UL;
static constexpr int64_t BLOCK_16 = 16L;
static constexpr uint64_t C0_SIZE_B8 = 32UL;
static constexpr uint64_t C0_SIZE_B4 = 64UL;

/* ========================================================================== */
/* Macros                                                                     */
/* ========================================================================== */

#define LAUNCH_KERNEL_IMPL(FULL_LOAD_MODE)                                                                       \
    quant_matmul_activation_quant_kernel<A_TYPE, B_TYPE, A_TYPE, LAYOUT_A, LAYOUT_B, FULL_LOAD_MODE>             \
        <<<p.blockNum, 0, p.stream>>>(p.dA, p.dB, p.dBias, p.dScaleA, p.dScaleB, p.dY, p.dYScale, p.m, p.k, p.n, \
                                      p.baseM, p.baseN, p.baseK, p.kL1, p.scaleKL1, p.l1BufferNum, p.dbL0C,      \
                                      p.biasElements)

#define DISPATCH_TRANS(A_TYPE, B_TYPE, TRANS_A, TRANS_B, IS_NZ, FULL_LOAD_MODE)                      \
    do {                                                                                             \
        if (TRANS_A) {                                                                               \
            if (TRANS_B) {                                                                           \
                if (IS_NZ) {                                                                         \
                    LaunchKernel<A_TYPE, B_TYPE, true, true, true, FULL_LOAD_MODE>(launchParams);    \
                } else {                                                                             \
                    LaunchKernel<A_TYPE, B_TYPE, true, true, false, FULL_LOAD_MODE>(launchParams);   \
                }                                                                                    \
            } else {                                                                                 \
                if (IS_NZ) {                                                                         \
                    LaunchKernel<A_TYPE, B_TYPE, true, false, true, FULL_LOAD_MODE>(launchParams);   \
                } else {                                                                             \
                    LaunchKernel<A_TYPE, B_TYPE, true, false, false, FULL_LOAD_MODE>(launchParams);  \
                }                                                                                    \
            }                                                                                        \
        } else {                                                                                     \
            if (TRANS_B) {                                                                           \
                if (IS_NZ) {                                                                         \
                    LaunchKernel<A_TYPE, B_TYPE, false, true, true, FULL_LOAD_MODE>(launchParams);   \
                } else {                                                                             \
                    LaunchKernel<A_TYPE, B_TYPE, false, true, false, FULL_LOAD_MODE>(launchParams);  \
                }                                                                                    \
            } else {                                                                                 \
                if (IS_NZ) {                                                                         \
                    LaunchKernel<A_TYPE, B_TYPE, false, false, true, FULL_LOAD_MODE>(launchParams);  \
                } else {                                                                             \
                    LaunchKernel<A_TYPE, B_TYPE, false, false, false, FULL_LOAD_MODE>(launchParams); \
                }                                                                                    \
            }                                                                                        \
        }                                                                                            \
    } while (0)

/* ========================================================================== */
/* CLI argument parsing                                                       */
/* ========================================================================== */

struct CliArgs {
    int64_t m = 0;
    int64_t k = 0;
    int64_t n = 0;
    int64_t bias = 0;
    std::string aDtype;
    std::string bDtype;
    bool transA = false;
    bool transB = false;
    std::string format = "(ND,NZ)";
    int64_t baseM = 0;
    int64_t baseN = 0;
    int64_t baseK = 0;
    int64_t kL1 = 0;
    int64_t scaleKL1 = 0;
    int64_t l1Buffers = 2;
    int64_t dbL0C = 1;
    bool aFullLoad = false;
};

static bool ParseBool(const char* s)
{
    std::string str(s);
    return str == "true" || str == "1" || str == "True";
}

static bool ParseCliArgs(int argc, const char** argv, CliArgs& args)
{
    if (argc != 18) {
        std::fprintf(stderr,
                     "Usage: %s <m> <k> <n> <bias> <a_dtype> <b_dtype>"
                     " <transA> <transB> <format> <base_m> <base_n> <base_k> <tile_k_l1> <scale_k_l1>"
                     " <l1_buffers> <db_l0c> <a_full_load>\n",
                     argv[0]);
        return false;
    }

    args.m = std::atoll(argv[1]);
    args.k = std::atoll(argv[2]);
    args.n = std::atoll(argv[3]);
    args.bias = std::atoll(argv[4]);
    args.aDtype = argv[5];
    args.bDtype = argv[6];
    args.transA = ParseBool(argv[7]);
    args.transB = ParseBool(argv[8]);
    args.format = argv[9];

    args.baseM = std::atoll(argv[10]);
    args.baseN = std::atoll(argv[11]);
    args.baseK = std::atoll(argv[12]);
    args.kL1 = std::atoll(argv[13]);
    args.scaleKL1 = std::atoll(argv[14]);
    args.l1Buffers = std::atoll(argv[15]);
    args.dbL0C = std::atoll(argv[16]);
    args.aFullLoad = ParseBool(argv[17]);

    // Validation
    if (args.m <= 0 || args.k <= 0 || args.n <= 0) {
        std::fprintf(stderr, "Error: M, K, N must be positive integers.\n");
        return false;
    }
    if (args.bias != 0 && args.bias != args.n) {
        std::fprintf(stderr, "Error: bias (%ld) must equal n (%ld) or be 0.\n", args.bias, args.n);
        return false;
    }
    if (args.aDtype != "fp8_e4m3" && args.aDtype != "fp8_e5m2" && args.aDtype != "fp4_e2m1") {
        std::fprintf(stderr, "Error: A dtype must be fp8_e4m3, fp8_e5m2, or fp4_e2m1.\n");
        return false;
    }
    if (args.bDtype != "fp8_e4m3" && args.bDtype != "fp4_e2m1") {
        std::fprintf(stderr, "Error: B dtype must be fp8_e4m3 or fp4_e2m1.\n");
        return false;
    }
    bool aIsFp4 = args.aDtype == "fp4_e2m1";
    bool bIsFp4 = args.bDtype == "fp4_e2m1";
    if (aIsFp4 != bIsFp4) {
        std::fprintf(stderr, "Error: FP4*FP8 mixed dtype is not supported by hardware (got a=%s b=%s).\n",
                     args.aDtype.c_str(), args.bDtype.c_str());
        return false;
    }
    if (args.format != "(ND,ND)" && args.format != "(ND,NZ)") {
        std::fprintf(stderr, "Error: format must be (ND,ND) or (ND,NZ) (got '%s').\n", args.format.c_str());
        return false;
    }
    return true;
}

/* ========================================================================== */
/* Dtype utilities                                                            */
/* ========================================================================== */

static bool IsFp4Dtype(const std::string& dtype) { return dtype == "fp4_e2m1"; }

static size_t DtypeSize(const std::string& dtype)
{
    if (dtype == "fp8_e4m3" || dtype == "fp8_e5m2" || dtype == "fp4_e2m1") {
        return 1;
    }
    std::fprintf(stderr, "Unknown dtype: %s\n", dtype.c_str());
    return 0;
}

static size_t ElementCountToBytes(int64_t count, const std::string& dtype)
{
    if (IsFp4Dtype(dtype)) {
        return static_cast<size_t>((count + 1) / 2) * DtypeSize(dtype);
    }
    return static_cast<size_t>(count) * DtypeSize(dtype);
}

/* ========================================================================== */
/* NZ format utilities (weight B is always NZ)                                */
/* ========================================================================== */

static uint64_t GetC0Size(const std::string& dtype) { return IsFp4Dtype(dtype) ? C0_SIZE_B4 : C0_SIZE_B8; }

static int64_t CalcNZElementCount(int64_t k, int64_t n, const std::string& dtype, bool transB)
{
    uint64_t c0Size = GetC0Size(dtype);
    if (transB) {
        int64_t kCeil = CeilAlign(k, static_cast<int64_t>(c0Size));
        int64_t nCeil = CeilAlign(n, BLOCK_16);
        return kCeil * nCeil;
    }
    int64_t kCeil = CeilAlign(k, BLOCK_16);
    int64_t nCeil = CeilAlign(n, static_cast<int64_t>(c0Size));
    return kCeil * nCeil;
}

/* ========================================================================== */
/* Device-side kernel wrapper (template-based)                                */
/* ========================================================================== */

using ProblemShape = AscendC::Te::Shape<int64_t, int64_t, int64_t, int64_t>;

template <class AType, class BType, class CType, class LayoutA, class LayoutB, uint64_t FullLoadMode>
__global__ __aicore__ void quant_matmul_activation_quant_kernel(GM_ADDR aGm, GM_ADDR bGm, GM_ADDR biasGm,
                                                                GM_ADDR scaleAGm, GM_ADDR scaleBGm, GM_ADDR yGm,
                                                                GM_ADDR yScaleGm, int64_t m, int64_t k, int64_t n,
                                                                uint64_t baseM, uint64_t baseN, uint64_t baseK,
                                                                uint64_t kL1, uint64_t scaleKL1, uint64_t l1BufferNum,
                                                                uint64_t dbL0C, uint64_t biasElements)
{
    KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_MIX_AIC_1_2);
    AscendC::InitSocState();
    using OutType = CType;
    using MatmulOutType = float;
    using BiasType = float;
    using LayoutC = AscendC::Te::NDExtLayoutPtn;
    using LayoutBias = AscendC::Te::NDExtLayoutPtn;
    using DispatchPolicy = Blaze::Gemm::MatmulWithScaleMx<FullLoadMode, false,
                                                          Blaze::Gemm::KernelMmadWithScaleMxActivationQuant,
                                                          Blaze::Gemm::L0C2UB_MODE_DUAL_DST_SPLIT_M>;
    using BlockScheduler = Blaze::Gemm::Block::BlockSchedulerQuantBatchMatmulV3<ProblemShape, FullLoadMode, LayoutA,
                                                                                LayoutB, AType>;
    using BlockMmad = Blaze::Gemm::Block::BlockMmad<DispatchPolicy, AType, LayoutA, BType, LayoutB, MatmulOutType,
                                                    LayoutC, BiasType, LayoutBias>;
    using BlockEpilogue = Blaze::Epilogue::Block::BlockEpilogueGeluMxQuant<OutType, MatmulOutType>;
    using Kernel = Blaze::Gemm::Kernel::GemmUniversal<ProblemShape, BlockMmad, BlockEpilogue, BlockScheduler>;

    typename Kernel::Params params{};
    params.problemShape = ProblemShape{m, n, k, 1};
    params.mmadParams = {aGm, bGm, yGm, biasGm, scaleAGm, scaleBGm};
    float dtypeMaxVal = 0.0f;
    if constexpr (AscendC::IsSameType<OutType, fp4x2_e2m1_t>::value) {
        dtypeMaxVal = 6.0f;
    }
    params.epilogueParams = {yGm,
                             yScaleGm,
                             static_cast<uint32_t>(baseM),
                             static_cast<uint32_t>(baseN),
                             Blaze::Epilogue::Block::GeluAlg::TANH,
                             Blaze::Epilogue::Block::QuantAlg::OCP,
                             Blaze::Epilogue::Block::ROUND_MODE_FP4::RINT,
                             dtypeMaxVal};
    params.l1Params = {kL1, scaleKL1, l1BufferNum};
    params.schParams = {static_cast<int64_t>(baseM), static_cast<int64_t>(baseN), 1, 1, 1, 1, 0, 0};
    params.qbmmParams = {1,
                         1,
                         1,
                         1,
                         1,
                         1,
                         1,
                         1,
                         1,
                         1,
                         1,
                         1,
                         0,
                         static_cast<uint32_t>(baseM),
                         static_cast<uint32_t>(baseN),
                         static_cast<uint32_t>(baseK),
                         biasElements != 0U ? 1U : 0U,
                         static_cast<uint32_t>(dbL0C)};
    Kernel kernel;
    kernel(params);
}

/* ========================================================================== */
/* Host-side kernel launcher                                                  */
/* ========================================================================== */

namespace {

struct LaunchParams {
    uint8_t* dA;
    uint8_t* dB;
    uint8_t* dBias;
    uint8_t* dScaleA;
    uint8_t* dScaleB;
    uint8_t* dY;
    uint8_t* dYScale;
    int64_t m, n, k;
    int64_t blockNum;
    uint64_t baseM, baseN, baseK;
    uint64_t kL1, scaleKL1, l1BufferNum, dbL0C, biasElements;
    aclrtStream stream;
};

template <class A_TYPE, class B_TYPE, bool TransA, bool TransB, bool IsNzFormat, uint64_t FullLoadMode>
void LaunchKernel(const LaunchParams& p)
{
    using LAYOUT_A = std::conditional_t<TransA, AscendC::Te::DNExtLayoutPtn, AscendC::Te::NDExtLayoutPtn>;
    using LAYOUT_B = std::conditional_t<
        IsNzFormat, std::conditional_t<TransB, AscendC::Te::ZNLayoutPtn, AscendC::Te::NZLayoutPtn>,
        std::conditional_t<TransB, AscendC::Te::DNExtLayoutPtn, AscendC::Te::NDExtLayoutPtn>>;

    LAUNCH_KERNEL_IMPL(FullLoadMode);
}

template <class A_TYPE, class B_TYPE, uint64_t FullLoadMode>
void LaunchByTrans(const CliArgs& args, bool isNzFormat, const LaunchParams& launchParams)
{
    DISPATCH_TRANS(A_TYPE, B_TYPE, args.transA, args.transB, isNzFormat, FullLoadMode);
}

template <class A_TYPE, class B_TYPE>
void LaunchByFullLoad(const CliArgs& args, bool isNzFormat, const LaunchParams& launchParams)
{
    if (args.aFullLoad) {
        LaunchByTrans<A_TYPE, B_TYPE, Blaze::Gemm::A_FULL_LOAD_MODE>(args, isNzFormat, launchParams);
    } else {
        LaunchByTrans<A_TYPE, B_TYPE, Blaze::Gemm::NONE_FULL_LOAD_MODE>(args, isNzFormat, launchParams);
    }
}

} // namespace

/* ========================================================================== */
/* Host-side runner                                                           */
/* ========================================================================== */

static void Run(const CliArgs& args)
{
    aclrtStream stream{nullptr};
    ACLDeviceGuard guard(stream);

    int64_t blockNum = GetAicCoreNum();
    if (blockNum <= 0) {
        std::cerr << "blockNum cannot be less than 0, but current: " << blockNum << std::endl;
        return;
    }

    const uint64_t scaleK = static_cast<uint64_t>(CeilDiv(args.k, static_cast<int64_t>(MXFP_DIVISOR_SIZE))) *
                            (MXFP_DIVISOR_SIZE / GROUP_SIZE);
    const uint64_t scaleN = static_cast<uint64_t>(CeilDiv(args.n, static_cast<int64_t>(MXFP_DIVISOR_SIZE))) *
                            (MXFP_DIVISOR_SIZE / GROUP_SIZE);
    const size_t aSize = ElementCountToBytes(args.m * args.k, args.aDtype);
    bool isNzFormat = (args.format == "(ND,NZ)");
    size_t bSize;
    if (isNzFormat) {
        int64_t nzElementCount = CalcNZElementCount(args.k, args.n, args.bDtype, args.transB);
        bSize = ElementCountToBytes(nzElementCount, args.bDtype);
    } else {
        bSize = ElementCountToBytes(args.k * args.n, args.bDtype);
    }
    const size_t biasSize = args.bias > 0 ? static_cast<size_t>(args.bias) * sizeof(float) : 1;
    const size_t scaleASize = static_cast<size_t>(args.m) * scaleK;
    const size_t scaleBSize = static_cast<size_t>(args.n) * scaleK;
    const size_t ySize = ElementCountToBytes(args.m * args.n, args.aDtype);
    const size_t yScaleSize = static_cast<size_t>(args.m) * scaleN;

    std::string inputDir = "./input";
    std::string outputDir = "./output";

    // Allocate host buffers
    std::vector<uint8_t> hostA(aSize);
    std::vector<uint8_t> hostB(bSize);
    std::vector<uint8_t> hostBias(biasSize, 0);
    std::vector<uint8_t> hostScaleA(scaleASize);
    std::vector<uint8_t> hostScaleB(scaleBSize);
    std::vector<uint8_t> hostY(ySize, 0);
    std::vector<uint8_t> hostYScale(yScaleSize, 0);

    std::cout << "[INFO] Reading " << inputDir << "/input_a.bin (" << aSize << " bytes)..." << std::endl;
    if (!ReadFile(inputDir + "/input_a.bin", hostA.data(), aSize)) {
        std::cerr << "Failed to read input A" << std::endl;
        return;
    }
    std::cout << "[INFO] Reading " << inputDir << "/input_b.bin (" << bSize << " bytes)..." << std::endl;
    if (!ReadFile(inputDir + "/input_b.bin", hostB.data(), bSize)) {
        std::cerr << "Failed to read input B" << std::endl;
        return;
    }
    std::cout << "[INFO] Reading " << inputDir << "/scale_a.bin (" << scaleASize << " bytes)..." << std::endl;
    if (!ReadFile(inputDir + "/scale_a.bin", hostScaleA.data(), scaleASize)) {
        std::cerr << "Failed to read scale A" << std::endl;
        return;
    }
    std::cout << "[INFO] Reading " << inputDir << "/scale_b.bin (" << scaleBSize << " bytes)..." << std::endl;
    if (!ReadFile(inputDir + "/scale_b.bin", hostScaleB.data(), scaleBSize)) {
        std::cerr << "Failed to read scale B" << std::endl;
        return;
    }
    if (args.bias > 0) {
        std::cout << "[INFO] Reading " << inputDir << "/bias.bin (" << biasSize << " bytes)..." << std::endl;
        if (!ReadFile(inputDir + "/bias.bin", hostBias.data(), biasSize)) {
            std::cerr << "Failed to read bias" << std::endl;
            return;
        }
    }

    // Allocate device buffers
    uint8_t* deviceA{nullptr};
    uint8_t* deviceB{nullptr};
    uint8_t* deviceBias{nullptr};
    uint8_t* deviceScaleA{nullptr};
    uint8_t* deviceScaleB{nullptr};
    uint8_t* deviceY{nullptr};
    uint8_t* deviceYScale{nullptr};

    ACL_CHECK(aclrtMalloc(reinterpret_cast<void**>(&deviceA), aSize, ACL_MEM_MALLOC_HUGE_FIRST));
    ACL_CHECK(aclrtMalloc(reinterpret_cast<void**>(&deviceB), bSize, ACL_MEM_MALLOC_HUGE_FIRST));
    ACL_CHECK(aclrtMalloc(reinterpret_cast<void**>(&deviceBias), biasSize, ACL_MEM_MALLOC_HUGE_FIRST));
    ACL_CHECK(aclrtMalloc(reinterpret_cast<void**>(&deviceScaleA), scaleASize, ACL_MEM_MALLOC_HUGE_FIRST));
    ACL_CHECK(aclrtMalloc(reinterpret_cast<void**>(&deviceScaleB), scaleBSize, ACL_MEM_MALLOC_HUGE_FIRST));
    ACL_CHECK(aclrtMalloc(reinterpret_cast<void**>(&deviceY), ySize, ACL_MEM_MALLOC_HUGE_FIRST));
    ACL_CHECK(aclrtMalloc(reinterpret_cast<void**>(&deviceYScale), yScaleSize, ACL_MEM_MALLOC_HUGE_FIRST));

    ACL_CHECK(aclrtMemcpy(deviceA, aSize, hostA.data(), aSize, ACL_MEMCPY_HOST_TO_DEVICE));
    ACL_CHECK(aclrtMemcpy(deviceB, bSize, hostB.data(), bSize, ACL_MEMCPY_HOST_TO_DEVICE));
    ACL_CHECK(aclrtMemcpy(deviceBias, biasSize, hostBias.data(), biasSize, ACL_MEMCPY_HOST_TO_DEVICE));
    ACL_CHECK(aclrtMemcpy(deviceScaleA, scaleASize, hostScaleA.data(), scaleASize, ACL_MEMCPY_HOST_TO_DEVICE));
    ACL_CHECK(aclrtMemcpy(deviceScaleB, scaleBSize, hostScaleB.data(), scaleBSize, ACL_MEMCPY_HOST_TO_DEVICE));

    // Print execution summary
    std::cout << "============================================================" << std::endl;
    std::cout << "  QuantMatmulActivationQuant MX — Execution Summary" << std::endl;
    std::cout << "============================================================" << std::endl;
    std::cout << "  Shape    : M=" << args.m << ", K=" << args.k << ", N=" << args.n << std::endl;
    std::cout << "  A Dtype  : " << args.aDtype << " (also C/Y dtype)" << std::endl;
    std::cout << "  B Dtype  : " << args.bDtype << " (weight NZ)" << std::endl;
    std::cout << "  transA   : " << (args.transA ? "true" : "false") << std::endl;
    std::cout << "  transB   : " << (args.transB ? "true" : "false") << std::endl;
    std::cout << "  Format   : " << args.format << std::endl;
    std::cout << "  Bias     : " << args.bias << " (float32)" << std::endl;
    std::cout << "  L0 Tile  : [" << args.baseM << ", " << args.baseN << ", " << args.baseK << "]" << std::endl;
    std::cout << "  L1 kL1   : " << args.kL1 << std::endl;
    std::cout << "  scaleKL1 : " << args.scaleKL1 << std::endl;
    std::cout << "  l1Buffers: " << args.l1Buffers << std::endl;
    std::cout << "  dbL0C    : " << args.dbL0C << std::endl;
    std::cout << "  AFullLoad: " << (args.aFullLoad ? "true" : "false") << std::endl;
    std::cout << "  BlockNum : " << blockNum << std::endl;
    std::cout << "============================================================" << std::endl;

    std::cout << "[INFO] Launching kernel..." << std::endl;

    LaunchParams launchParams = {deviceA,
                                 deviceB,
                                 deviceBias,
                                 deviceScaleA,
                                 deviceScaleB,
                                 deviceY,
                                 deviceYScale,
                                 args.m,
                                 args.n,
                                 args.k,
                                 blockNum,
                                 static_cast<uint64_t>(args.baseM),
                                 static_cast<uint64_t>(args.baseN),
                                 static_cast<uint64_t>(args.baseK),
                                 static_cast<uint64_t>(args.kL1),
                                 static_cast<uint64_t>(args.scaleKL1),
                                 static_cast<uint64_t>(args.l1Buffers),
                                 static_cast<uint64_t>(args.dbL0C),
                                 static_cast<uint64_t>(args.bias),
                                 stream};

    if (args.aDtype == "fp8_e4m3" && args.bDtype == "fp8_e4m3") {
        LaunchByFullLoad<fp8_e4m3fn_t, fp8_e4m3fn_t>(args, isNzFormat, launchParams);
    } else if (args.aDtype == "fp8_e5m2" && args.bDtype == "fp8_e4m3") {
        LaunchByFullLoad<fp8_e5m2_t, fp8_e4m3fn_t>(args, isNzFormat, launchParams);
    } else if (args.aDtype == "fp4_e2m1" && args.bDtype == "fp4_e2m1") {
        LaunchByFullLoad<fp4x2_e2m1_t, fp4x2_e2m1_t>(args, isNzFormat, launchParams);
    } else {
        std::fprintf(stderr,
                     "Unsupported A/B dtype combination: a=%s b=%s.\n"
                     "Supported: fp8_e4m3*fp8_e4m3, fp8_e5m2*fp8_e4m3, fp4_e2m1*fp4_e2m1.\n",
                     args.aDtype.c_str(), args.bDtype.c_str());
        std::exit(1);
    }

    ACL_CHECK(aclrtSynchronizeStream(stream));

    ACL_CHECK(aclrtMemcpy(hostY.data(), ySize, deviceY, ySize, ACL_MEMCPY_DEVICE_TO_HOST));
    ACL_CHECK(aclrtMemcpy(hostYScale.data(), yScaleSize, deviceYScale, yScaleSize, ACL_MEMCPY_DEVICE_TO_HOST));

    // Write outputs
    std::string yPath = outputDir + "/npu_y.bin";
    std::string yScalePath = outputDir + "/npu_y_scale.bin";
    std::cout << "[INFO] Writing " << yPath << " (" << ySize << " bytes)..." << std::endl;
    if (!WriteFile(yPath, hostY.data(), ySize)) {
        std::cerr << "Failed to write output Y" << std::endl;
    }
    std::cout << "[INFO] Writing " << yScalePath << " (" << yScaleSize << " bytes)..." << std::endl;
    if (!WriteFile(yScalePath, hostYScale.data(), yScaleSize)) {
        std::cerr << "Failed to write output Y_scale" << std::endl;
    }
    std::cout << "[INFO] Kernel execution completed successfully." << std::endl;

    ACL_CHECK(aclrtFree(deviceA));
    ACL_CHECK(aclrtFree(deviceB));
    ACL_CHECK(aclrtFree(deviceBias));
    ACL_CHECK(aclrtFree(deviceScaleA));
    ACL_CHECK(aclrtFree(deviceScaleB));
    ACL_CHECK(aclrtFree(deviceY));
    ACL_CHECK(aclrtFree(deviceYScale));
}

/* ========================================================================== */
/* Entry point                                                                */
/* ========================================================================== */

int main(int argc, const char** argv)
{
    CliArgs args;
    if (!ParseCliArgs(argc, argv, args)) {
        return 1;
    }

    Run(args);
    return 0;
}
