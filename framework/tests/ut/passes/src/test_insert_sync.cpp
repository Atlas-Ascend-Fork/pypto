/**
 * Copyright (c) 2025 Huawei Technologies Co., Ltd.
 * This program is free software, you can redistribute it and/or modify it under the terms and conditions of
 * CANN Open Software License Agreement Version 2.0 (the "License").
 * Please refer to the License for details. You may not use this file except in compliance with the License.
 * THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND, EITHER EXPRESS OR IMPLIED,
 * INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY, OR FITNESS FOR A PARTICULAR PURPOSE.
 * See LICENSE in the root of the software repository for the full text of the License.
 */

/*!
 * \file test_insert_sync.cpp
 * \brief Unit test for InsertSync.
 */
#include <gtest/gtest.h>
#include "symbolic_scalar_test_utils.h"
#include "computational_graph_builder.h"
#include "pass_test_utils.h"
#include "tilefwk/platform.h"
#include "interface/operation/attribute.h"
#include "interface/tensor/irbuilder.h"
#define private public
#include "passes/block_graph_pass/insert_sync.h"
#include "passes/pass_utils/pass_common_defs.h"
#include "ut_json/ut_json_tool.h"

namespace npu {
namespace tile_fwk {
constexpr int VF_SCOPE_A = VF_CLUSTER_ID_START;
constexpr int VF_SCOPE_B = VF_CLUSTER_ID_START + 1;
constexpr int IS_NUM1 = 1;
constexpr int IS_NUM2 = 2;
constexpr int IS_NUM3 = 3;
constexpr int IS_NUM4 = 4;
constexpr int IS_NUM5 = 5;
constexpr int IS_NUM6 = 6;
constexpr int IS_NUM7 = 7;
constexpr int IS_NUM8 = 8;
constexpr int IS_NUM9 = 9;
constexpr int IS_NUM10 = 10;
constexpr int IS_NUM11 = 11;
constexpr int IS_NUM12 = 12;
constexpr int IS_NUM16 = 16;
constexpr int IS_NUM18 = 18;
constexpr int IS_NUM19 = 19;
constexpr int IS_NUM20 = 20;
constexpr int IS_NUM29 = 29;
constexpr int IS_NUM30 = 30;
constexpr int IS_NUM32 = 32;
constexpr int IS_NUM39 = 39;
constexpr int IS_NUM40 = 40;
constexpr int IS_NUM49 = 49;
constexpr int IS_NUM50 = 50;
constexpr int IS_NUM59 = 59;
constexpr int IS_NUM60 = 60;
constexpr int IS_NUM69 = 69;
constexpr int IS_NUM70 = 70;
constexpr int IS_NUM79 = 79;
constexpr int IS_NUM80 = 80;
constexpr int IS_NUM89 = 89;
constexpr int IS_NUM90 = 90;
constexpr int IS_NUM99 = 99;
constexpr int IS_NUM100 = 100;
constexpr int IS_NUM101 = 101;
constexpr int IS_NUM109 = 109;
constexpr int IS_NUM110 = 110;
constexpr int IS_NUM119 = 119;
constexpr int IS_NUM120 = 120;
constexpr int IS_NUM129 = 129;
constexpr int IS_NUM130 = 130;
constexpr int IS_NUM139 = 139;
constexpr int IS_NUM140 = 140;
constexpr int IS_NUM149 = 149;
constexpr int IS_NUM150 = 150;
constexpr int IS_NUM159 = 159;
constexpr int IS_NUM160 = 160;
constexpr int IS_NUM169 = 169;
constexpr int IS_NUM170 = 170;
constexpr int IS_NUM179 = 179;
constexpr int IS_NUM180 = 180;
constexpr int IS_NUM189 = 189;
constexpr int IS_NUM190 = 190;
constexpr int IS_NUM199 = 199;
constexpr int IS_NUM200 = 200;
constexpr int IS_NUM209 = 209;
constexpr int IS_NUM210 = 210;
constexpr int IS_NUM219 = 219;
constexpr int IS_NUM220 = 220;
constexpr int IS_NUM229 = 229;
constexpr int IS_NUM230 = 230;
constexpr int IS_NUM239 = 239;
constexpr int IS_NUM240 = 240;
constexpr int IS_NUM249 = 249;
constexpr int IS_NUM250 = 250;
constexpr int IS_NUM259 = 259;
constexpr int IS_NUM260 = 260;
constexpr int IS_NUM269 = 269;
constexpr int IS_NUM270 = 270;
constexpr int IS_NUM279 = 279;
constexpr int IS_NUM280 = 280;
constexpr int IS_NUM289 = 289;
constexpr int IS_NUM290 = 290;
constexpr int IS_NUM299 = 299;
constexpr int IS_NUM300 = 300;
constexpr int IS_NUM499 = 499;
constexpr int IS_NUM500 = 500;
constexpr int IS_NUM600 = 600;
constexpr int IS_NUM699 = 699;
constexpr int IS_NUM700 = 700;
constexpr int IS_NUM800 = 800;
constexpr int IS_NUM900 = 900;
constexpr int IS_NUM1000 = 1000;
constexpr int IS_NUM1100 = 1100;
class InsertSyncTest : public ::testing::Test {
public:
    static void SetUpTestCase() {}

    static void TearDownTestCase() {}

    void SetUp() override
    {
        Program::GetInstance().Reset();
        config::Reset();
        config::SetHostOption(COMPILE_STAGE, CS_EXECUTE_GRAPH);
        config::SetPlatformConfig(KEY_ENABLE_COST_MODEL, false);
    }
    void TearDown() override {}

    void AdjustCopyOpTileCfg(Operation& op, TileOpCfg& opcfg)
    {
        opcfg.aivCore_ = AIVCore::AIV0;
        if (op.GetOpcode() == Opcode::OP_COPY_IN) {
            opcfg.pipeIdStart_ = PipeType::PIPE_MTE2;
            opcfg.pipeIdEnd_ = PipeType::PIPE_MTE2;
            opcfg.coreType_ = CoreType::AIV;
        } else if (op.GetOpcode() == Opcode::OP_COPY_OUT) {
            opcfg.pipeIdStart_ = PipeType::PIPE_MTE3;
            opcfg.pipeIdEnd_ = PipeType::PIPE_MTE3;
            opcfg.coreType_ = CoreType::AIV;
        }
    }

    void BuildDeps(PipeSync& ps, DataDependencySearcher& dataDependencySearcher, std::vector<Operation*>& opLogPtr,
                   std::vector<IndexOp>& synced)
    {
        for (size_t i = 0; i < opLogPtr.size(); i++) {
            auto opcfg = OpcodeManager::Inst().GetTileOpCfg(opLogPtr[i]->GetOpcode());
            AdjustCopyOpTileCfg(*opLogPtr[i], opcfg);
            PipeSync::DepOp op(i, {opcfg.pipeIdStart_, opcfg.pipeIdEnd_, opcfg.coreType_, opcfg.aivCore_});
            PipeSync::DepOp& currOp = ps.depOps_.emplace_back(op);
            auto dataDependencySet = dataDependencySearcher.Find(opLogPtr[i]);
            for (auto it = dataDependencySet.rbegin(); it != dataDependencySet.rend(); it++) {
                size_t k = *it;
                PipeSync::DepOp& prevOp = ps.depOps_[k];
                if (ps.HasDataDependency(*opLogPtr[k], *opLogPtr[i])) {
                    ps.UpdateDep(currOp, prevOp);
                }
            }
            dataDependencySearcher.Insert(opLogPtr[i], i);
            ps.EnqueueOp(currOp, opLogPtr, synced);
        }
    }
};

TEST_F(InsertSyncTest, TestEnableDebug)
{
    auto rootFuncPtr = std::make_shared<Function>(Program::GetInstance(), "TestParams", "TestParams", nullptr);
    rootFuncPtr->rootFunc_ = rootFuncPtr.get();
    auto currFunctionPtr = std::make_shared<Function>(Program::GetInstance(), "TestAddParams", "TestAddParams",
                                                      rootFuncPtr.get());
    EXPECT_TRUE(currFunctionPtr != nullptr);
    rootFuncPtr->rootFunc_->programs_.emplace(currFunctionPtr->GetFuncMagic(), currFunctionPtr.get());

    // Prepare the graph
    std::vector<int64_t> shape = {IS_NUM8, IS_NUM16};
    auto shapeImme = OpImmediate::Specified(shape);
    auto incast1 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    auto incast2 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    auto ubTensor1 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    auto ubTensor2 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    auto ubTensor3 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    auto outCast = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));

    auto& copy_op1 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {incast1}, {ubTensor1});
    (void)copy_op1;
    auto& copy_op2 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {incast2}, {ubTensor2});
    (void)copy_op2;
    auto& add_op = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_ADD, {ubTensor1, ubTensor2},
                                                  {ubTensor3});
    (void)add_op;
    auto& copy_out_op = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_OUT, {ubTensor3}, {outCast});
    (void)copy_out_op;
    currFunctionPtr->inCasts_.push_back(incast1);
    currFunctionPtr->inCasts_.push_back(incast2);
    currFunctionPtr->outCasts_.push_back(outCast);
    InsertSync syncPass;
    syncPass.SetEnableDebug(true);
    syncPass.RunOnFunction(*rootFuncPtr);
    EXPECT_TRUE(true);
}

std::vector<std::shared_ptr<LogicalTensor>> AddOpForTestFindDep(std::vector<Operation*>& opLogPtr,
                                                                std::shared_ptr<Function> currFunctionPtr)
{
    // Build graph
    std::vector<int64_t> shape1 = {IS_NUM16, IS_NUM16};
    std::vector<int64_t> shape2 = {IS_NUM8, IS_NUM16};
    auto tensor1 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape2, CreateTestConstIntVector(shape2));
    tensor1->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor1->memoryrange.start = 0;
    tensor1->memoryrange.end = IS_NUM100;
    auto tensor2 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape1, CreateTestConstIntVector(shape1));
    tensor2->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor2->memoryrange.start = 0;
    tensor2->memoryrange.end = IS_NUM200;
    auto tensor3 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape2, CreateTestConstIntVector(shape2));
    tensor3->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor3->memoryrange.start = IS_NUM300;
    tensor3->memoryrange.end = IS_NUM499;
    auto tensor4 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape2, CreateTestConstIntVector(shape2));
    tensor4->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor4->memoryrange.start = IS_NUM500;
    tensor4->memoryrange.end = IS_NUM699;
    auto tensor5 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape2, CreateTestConstIntVector(shape2));
    tensor5->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor5->memoryrange.start = IS_NUM700;
    tensor5->memoryrange.end = IS_NUM900;
    auto tensor6 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape2, CreateTestConstIntVector(shape2));
    tensor6->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor6->memoryrange.start = IS_NUM150;
    tensor6->memoryrange.end = IS_NUM200;
    auto& expend = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_EXPAND, {tensor1}, {tensor2});
    opLogPtr.emplace_back(&expend);
    auto& copyin1 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {tensor2}, {tensor3});
    opLogPtr.emplace_back(&copyin1);
    auto& copyin2 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {tensor2}, {tensor4});
    opLogPtr.emplace_back(&copyin2);
    auto& copyin3 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {tensor2}, {tensor5});
    opLogPtr.emplace_back(&copyin3);
    auto& exp = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_EXP, {tensor3}, {tensor6});
    opLogPtr.emplace_back(&exp);
    return {tensor1, tensor2, tensor3, tensor4, tensor5, tensor6};
}

void CheckDependencyForTestFindDep(PipeSync& ps, std::set<int> dataDependencySet, std::vector<Operation*>& opLogPtr,
                                   size_t i)
{
    for (auto it = dataDependencySet.rbegin(); it != dataDependencySet.rend(); it++) {
        size_t k = *it;
        // start tests
        if (i == IS_NUM1 && k == 0) {
            EXPECT_EQ(ps.CheckRawDependency(*opLogPtr[k], *opLogPtr[i]), true);
            EXPECT_EQ(ps.CheckWarDependency(*opLogPtr[k], *opLogPtr[i]), false);
            EXPECT_EQ(ps.CheckWawDependency(*opLogPtr[k], *opLogPtr[i]), false);
        }
        if (i == IS_NUM4 && k == 0) {
            EXPECT_EQ(ps.CheckRawDependency(*opLogPtr[k], *opLogPtr[i]), false);
            EXPECT_EQ(ps.CheckWarDependency(*opLogPtr[k], *opLogPtr[i]), false);
            EXPECT_EQ(ps.CheckWawDependency(*opLogPtr[k], *opLogPtr[i]), true);
        }
        if (i == IS_NUM4 && k == IS_NUM1) {
            EXPECT_EQ(ps.CheckRawDependency(*opLogPtr[k], *opLogPtr[i]), true);
            EXPECT_EQ(ps.CheckWarDependency(*opLogPtr[k], *opLogPtr[i]), true);
            EXPECT_EQ(ps.CheckWawDependency(*opLogPtr[k], *opLogPtr[i]), false);
        }
        // end tests
    }
}

void ProcessOpList(PipeSync& ps, DataDependencySearcher& dataDependencySearcher, std::vector<Operation*>& opLogPtr)
{
    ps.oriOpList_ = opLogPtr;
    for (auto& op : opLogPtr) {
        bool isCubeComponent = op->HasAttr(OpAttributeKey::isCube) && op->GetAttr<bool>(OpAttributeKey::isCube);
        if (!isCubeComponent) {
            op->SetAIVCore(AIVCore::AIV0);
        }
        ps.BuildTensorRangeMap(op);
    }
    dataDependencySearcher.ubTensorRangeMap = ps.ubTensorRangeMap;
}

TEST_F(InsertSyncTest, TestFindDep)
{
    auto rootFuncPtr = std::make_shared<Function>(Program::GetInstance(), "TestFindDep", "TestFindDep", nullptr);
    rootFuncPtr->rootFunc_ = rootFuncPtr.get();
    auto currFunctionPtr = std::make_shared<Function>(Program::GetInstance(), "TestFindDepLeaf", "TestFindDepLeaf",
                                                      rootFuncPtr.get());
    EXPECT_TRUE(currFunctionPtr != nullptr);
    rootFuncPtr->rootFunc_->programs_.emplace(currFunctionPtr->GetFuncMagic(), currFunctionPtr.get());

    std::vector<Operation*> opLogPtr;
    auto tensors = AddOpForTestFindDep(opLogPtr, currFunctionPtr);
    PipeSync ps;
    DataDependencySearcher dataDependencySearcher;
    ProcessOpList(ps, dataDependencySearcher, opLogPtr);
    for (size_t i = 0; i < opLogPtr.size(); i++) {
        auto opcfg = OpcodeManager::Inst().GetTileOpCfg(opLogPtr[i]->GetOpcode());
        AdjustCopyOpTileCfg(*opLogPtr[i], opcfg);
        PipeSync::DepOp op(i, {opcfg.pipeIdStart_, opcfg.pipeIdEnd_, opcfg.coreType_, opcfg.aivCore_});
        ps.depOps_.emplace_back(op);
        auto dataDependencySet = dataDependencySearcher.Find(opLogPtr[i]);
        // start tests
        if (i == IS_NUM1 || i == IS_NUM2 || i == IS_NUM3) {
            std::set<int> res = {0};
            EXPECT_EQ(dataDependencySet, res);
        }
        if (i == IS_NUM4) {
            std::set<int> res = {0, IS_NUM1, IS_NUM2, IS_NUM3};
            EXPECT_EQ(dataDependencySet, res);
        }
        // end tests
        CheckDependencyForTestFindDep(ps, dataDependencySet, opLogPtr, i);
        dataDependencySearcher.Insert(opLogPtr[i], i);
    }

    // test ignorable intra pipe dep
    EXPECT_EQ(ps.IgnorableIntraPipeDep(0, IS_NUM4, opLogPtr), false);
    tensors[1]->shape = {IS_NUM16, IS_NUM32, IS_NUM32};
    EXPECT_EQ(ps.IgnorableIntraPipeDep(0, IS_NUM4, opLogPtr), false);

    // test AdjustOpCfg
    auto opcfg1 = OpcodeManager::Inst().GetTileOpCfg(opLogPtr[1]->GetOpcode());
    EXPECT_EQ(ps.AdjustOpCfg(opcfg1, *opLogPtr[1]), FAILED);

    std::vector<int64_t> shape = {IS_NUM8, IS_NUM16};
    auto tensor7 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor7->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor7->memoryrange.start = IS_NUM1000;
    tensor7->memoryrange.end = IS_NUM1100;
    auto& copyout = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_OUT, {tensors[4]}, {tensor7});
    opLogPtr.emplace_back(&copyout);
    auto opcfg2 = OpcodeManager::Inst().GetTileOpCfg(opLogPtr[IS_NUM1]->GetOpcode());
    EXPECT_EQ(ps.AdjustOpCfg(opcfg2, *opLogPtr[IS_NUM5]), FAILED);
}

TEST_F(InsertSyncTest, TestTokenOnlyDependencyGeneratesSync)
{
    auto function = std::make_shared<Function>(Program::GetInstance(), "TestTokenOnlyDependencyGeneratesSync",
                                               "TestTokenOnlyDependencyGeneratesSync", nullptr);
    std::vector<int64_t> shape = {IS_NUM8, IS_NUM16};
    auto shapeImmediate = OpImmediate::Specified(shape);
    IRBuilder builder;
    auto gmInput = builder.CreateTensorVar(*function, DT_FP32, shape);
    auto producerOutput = builder.CreateTensorVar(*function, DT_FP32, shape);
    auto consumerInput = builder.CreateTensorVar(*function, DT_FP32, shape);
    auto consumerOutput = builder.CreateTensorVar(*function, DT_FP32, shape);
    gmInput->SetMemoryTypeBoth(MemoryType::MEM_DEVICE_DDR);
    producerOutput->SetMemoryTypeBoth(MemoryType::MEM_UB);
    consumerInput->SetMemoryTypeBoth(MemoryType::MEM_UB);
    consumerOutput->SetMemoryTypeBoth(MemoryType::MEM_UB);
    gmInput->memoryrange = TileRange(0, IS_NUM100, IS_NUM1);
    producerOutput->memoryrange = TileRange(0, IS_NUM100, IS_NUM2);
    consumerInput->memoryrange = TileRange(IS_NUM200, IS_NUM300, IS_NUM3);
    consumerOutput->memoryrange = TileRange(IS_NUM300, IS_NUM499, IS_NUM4);

    auto& producer = builder.CreateTensorOpStmt(*function, Opcode::OP_COPY_IN, {gmInput}, {producerOutput});
    producer.SetOpAttribute(std::make_shared<CopyOpAttribute>(OpImmediate::Specified({0, 0}), MemoryType::MEM_UB,
                                                              shapeImmediate, shapeImmediate));
    producer.SetAIVCore(AIVCore::AIV0);
    auto& consumer = builder.CreateTensorOpStmt(*function, Opcode::OP_CAST, {consumerInput}, {consumerOutput});
    consumer.SetAIVCore(AIVCore::AIV0);

    PipeSync ps;
    EXPECT_FALSE(ps.HasDataDependency(producer, consumer));
    auto token = builder.CreateTokenVar(ir::Span::Unknown());
    producer.result_token_ = {token};
    consumer.tokens_.push_back(token);
    auto& dependency = function->GetVarDependency();
    dependency.AddProducer(token, std::static_pointer_cast<const ir::Stmt>(function->operations_[0]));
    dependency.AddConsumer(token, std::static_pointer_cast<const ir::Stmt>(function->operations_[IS_NUM1]));
    EXPECT_TRUE(ps.HasDataDependency(producer, consumer));

    std::vector<Operation*> syncedOps;
    ASSERT_EQ(ps.InsertSync(*function, syncedOps), SUCCESS);
    bool hasSyncSrc = false;
    bool hasSyncDst = false;
    for (auto* op : syncedOps) {
        hasSyncSrc = hasSyncSrc || op->GetOpcode() == Opcode::OP_SYNC_SRC;
        hasSyncDst = hasSyncDst || op->GetOpcode() == Opcode::OP_SYNC_DST;
    }
    EXPECT_TRUE(hasSyncSrc);
    EXPECT_TRUE(hasSyncDst);
}

TEST_F(InsertSyncTest, TestTokenOnlyCrossCoreDependencyGeneratesCvSync)
{
    auto function = std::make_shared<Function>(Program::GetInstance(),
                                               "TestTokenOnlyCrossCoreDependencyGeneratesCvSync",
                                               "TestTokenOnlyCrossCoreDependencyGeneratesCvSync", nullptr);
    std::vector<int64_t> shape = {IS_NUM8, IS_NUM16};
    IRBuilder builder;
    auto l1Input = builder.CreateTensorVar(*function, DT_FP32, shape);
    auto l0aOutput = builder.CreateTensorVar(*function, DT_FP32, shape);
    auto ubInput = builder.CreateTensorVar(*function, DT_FP32, shape);
    auto ubOutput = builder.CreateTensorVar(*function, DT_FP32, shape);
    l1Input->SetMemoryTypeBoth(MemoryType::MEM_L1);
    l0aOutput->SetMemoryTypeBoth(MemoryType::MEM_L0A);
    ubInput->SetMemoryTypeBoth(MemoryType::MEM_UB);
    ubOutput->SetMemoryTypeBoth(MemoryType::MEM_UB);
    l1Input->memoryrange = TileRange(0, IS_NUM100, IS_NUM1);
    l0aOutput->memoryrange = TileRange(0, IS_NUM100, IS_NUM2);
    ubInput->memoryrange = TileRange(IS_NUM200, IS_NUM300, IS_NUM3);
    ubOutput->memoryrange = TileRange(IS_NUM300, IS_NUM499, IS_NUM4);

    auto& producer = builder.CreateTensorOpStmt(*function, Opcode::OP_L1_TO_L0A, {l1Input}, {l0aOutput});
    auto& consumer = builder.CreateTensorOpStmt(*function, Opcode::OP_CAST, {ubInput}, {ubOutput});
    consumer.SetAIVCore(AIVCore::AIV0);
    auto token = builder.CreateTokenVar(ir::Span::Unknown());
    producer.result_token_ = {token};
    consumer.tokens_.push_back(token);
    auto& dependency = function->GetVarDependency();
    dependency.AddProducer(token, std::static_pointer_cast<const ir::Stmt>(function->operations_[0]));
    dependency.AddConsumer(token, std::static_pointer_cast<const ir::Stmt>(function->operations_[IS_NUM1]));

    PipeSync ps;
    EXPECT_TRUE(ps.HasDataDependency(producer, consumer));
    std::vector<Operation*> syncedOps;
    ASSERT_EQ(ps.InsertSync(*function, syncedOps), SUCCESS);
    bool hasCvSyncSrc = false;
    bool hasCvSyncDst = false;
    for (auto* op : syncedOps) {
        hasCvSyncSrc = hasCvSyncSrc || op->GetOpcode() == Opcode::OP_CV_SYNC_SRC;
        hasCvSyncDst = hasCvSyncDst || op->GetOpcode() == Opcode::OP_CV_SYNC_DST;
    }
    EXPECT_TRUE(hasCvSyncSrc);
    EXPECT_TRUE(hasCvSyncDst);
}

TEST_F(InsertSyncTest, TestPhaseKernelProcess)
{
    auto rootFuncPtr = std::make_shared<Function>(Program::GetInstance(), "TestPhaseKernelProcess",
                                                  "TestPhaseKernelProcess", nullptr);
    rootFuncPtr->rootFunc_ = rootFuncPtr.get();
    auto currFunctionPtr = std::make_shared<Function>(Program::GetInstance(), "TestPhaseKernelProcessLeaf",
                                                      "TestPhaseKernelProcessLeaf", rootFuncPtr.get());
    EXPECT_TRUE(currFunctionPtr != nullptr);
    rootFuncPtr->rootFunc_->programs_.emplace(currFunctionPtr->GetFuncMagic(), currFunctionPtr.get());

    std::vector<int64_t> shape = {IS_NUM16, IS_NUM16};
    auto tensor1 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    auto tensor2 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    auto tensor3 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    auto tensor4 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    auto tensor5 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    auto tensor6 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    std::vector<Operation*> opLogPtr;
    auto& copyin1 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {tensor1}, {tensor3});
    opLogPtr.emplace_back(&copyin1);
    auto& copyin2 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {tensor2}, {tensor4});
    opLogPtr.emplace_back(&copyin2);
    auto& add = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_ADD, {tensor3, tensor4}, {tensor5});
    opLogPtr.emplace_back(&add);
    auto& copyout = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_OUT, {tensor5}, {tensor6});
    opLogPtr.emplace_back(&copyout);

    PipeSync ps;
    std::vector<Operation*> resLogPtr;
    ps.PhaseKernelProcess(*currFunctionPtr, opLogPtr, resLogPtr);
    EXPECT_EQ(resLogPtr[0]->GetOpcode(), Opcode::OP_PHASE1);
    EXPECT_EQ(resLogPtr[IS_NUM3]->GetOpcode(), Opcode::OP_PHASE2);
}

void AddOpForTestUpdateDep(std::vector<Operation*>& opLogPtr, std::shared_ptr<Function> currFunctionPtr)
{
    std::vector<int64_t> shape = {IS_NUM16, IS_NUM16};
    auto tensor1 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor1->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor1->memoryrange.start = 0;
    tensor1->memoryrange.end = IS_NUM100;
    auto tensor2 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor2->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor2->memoryrange.start = IS_NUM200;
    tensor2->memoryrange.end = IS_NUM300;
    auto tensor3 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor3->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor3->memoryrange.start = IS_NUM200;
    tensor3->memoryrange.end = IS_NUM300;
    auto tensor4 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor4->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor4->memoryrange.start = IS_NUM200;
    tensor4->memoryrange.end = IS_NUM300;
    auto tensor5 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor5->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor5->memoryrange.start = IS_NUM500;
    tensor5->memoryrange.end = IS_NUM600;
    auto tensor6 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor6->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor6->memoryrange.start = IS_NUM500;
    tensor6->memoryrange.end = IS_NUM600;
    auto tensor7 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor7->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor7->memoryrange.start = 0;
    tensor7->memoryrange.end = IS_NUM100;
    auto tensor8 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor8->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor8->memoryrange.start = IS_NUM101;
    tensor8->memoryrange.end = IS_NUM199;
    auto& copyin1 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {tensor1}, {tensor8});
    opLogPtr.emplace_back(&copyin1);
    auto& copyin2 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {tensor2}, {tensor3});
    opLogPtr.emplace_back(&copyin2);
    auto& cast1 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor3}, {tensor4});
    opLogPtr.emplace_back(&cast1);
    auto& cast2 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor5}, {tensor6});
    opLogPtr.emplace_back(&cast2);
    auto& copyout = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_OUT, {tensor6}, {tensor7});
    opLogPtr.emplace_back(&copyout);
}

TEST_F(InsertSyncTest, TestUpdateDep)
{
    auto rootFuncPtr = std::make_shared<Function>(Program::GetInstance(), "TestUpdateDep", "TestUpdateDep", nullptr);
    rootFuncPtr->rootFunc_ = rootFuncPtr.get();
    auto currFunctionPtr = std::make_shared<Function>(Program::GetInstance(), "TestUpdateDepLeaf", "TestUpdateDepLeaf",
                                                      rootFuncPtr.get());
    EXPECT_TRUE(currFunctionPtr != nullptr);
    rootFuncPtr->rootFunc_->programs_.emplace(currFunctionPtr->GetFuncMagic(), currFunctionPtr.get());

    std::vector<Operation*> opLogPtr;
    AddOpForTestUpdateDep(opLogPtr, currFunctionPtr);

    PipeSync ps;
    DataDependencySearcher dataDependencySearcher;
    ProcessOpList(ps, dataDependencySearcher, opLogPtr);
    for (size_t i = 0; i < opLogPtr.size(); i++) {
        auto opcfg = OpcodeManager::Inst().GetTileOpCfg(opLogPtr[i]->GetOpcode());
        AdjustCopyOpTileCfg(*opLogPtr[i], opcfg);
        PipeSync::DepOp op(i, {opcfg.pipeIdStart_, opcfg.pipeIdEnd_, opcfg.coreType_, opcfg.aivCore_});
        auto& currOp = ps.depOps_.emplace_back(op);
        auto dataDependencySet = dataDependencySearcher.Find(opLogPtr[i]);
        for (auto it = dataDependencySet.rbegin(); it != dataDependencySet.rend(); it++) {
            size_t k = *it;
            auto& prevOp = ps.depOps_[k];
            if (ps.HasDataDependency(*opLogPtr[k], *opLogPtr[i])) {
                // start tests
                ps.UpdateDep(currOp, prevOp);
                PipeSync::PipeCoreRealEx pcCurr(PipeType::PIPE_MTE3, CoreType::AIV, AIVCore::AIV0);
                PipeSync::PipeCoreRealEx pcSet1(PipeType::PIPE_V, CoreType::AIV, AIVCore::AIV0);
                PipeSync::PipeCoreRealEx pcSet2(PipeType::PIPE_MTE2, CoreType::AIV, AIVCore::AIV0);
                auto setPipeIdx1 = ps.latestPipeDep_[pcCurr].setPipes[pcSet1];
                auto setPipeIdx2 = ps.latestPipeDep_[pcCurr].setPipes[pcSet2];
                ps.latestPipeDep_[pcCurr].DumpPipeDepInfo();
                if (i == IS_NUM4 && k == IS_NUM3) {
                    EXPECT_EQ(setPipeIdx1, static_cast<size_t>(IS_NUM3));
                    EXPECT_EQ(setPipeIdx2, static_cast<size_t>(IS_NUM1));
                }
                if (i == IS_NUM4 && k == 0) {
                    EXPECT_EQ(setPipeIdx1, static_cast<size_t>(IS_NUM3));
                    EXPECT_EQ(setPipeIdx2, static_cast<size_t>(IS_NUM1));
                }
            }
        }
        dataDependencySearcher.Insert(opLogPtr[i], i);
    }
}

void AddOpForTestHandleEventID(std::vector<Operation*>& opLogPtr, std::shared_ptr<Function> currFunctionPtr)
{
    std::vector<int64_t> shape = {IS_NUM16, IS_NUM16};
    auto tensor1 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor1->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor1->memoryrange.start = 0;
    tensor1->memoryrange.end = IS_NUM99;
    auto tensor2 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor2->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor2->memoryrange.start = IS_NUM100;
    tensor2->memoryrange.end = IS_NUM199;
    auto tensor3 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor3->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor3->memoryrange.start = IS_NUM200;
    tensor3->memoryrange.end = IS_NUM300;
    auto tensor4 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor4->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor4->memoryrange.start = IS_NUM500;
    tensor4->memoryrange.end = IS_NUM600;
    auto tensor5 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor5->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor5->memoryrange.start = IS_NUM700;
    tensor5->memoryrange.end = IS_NUM800;
    auto& copyin1 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {tensor1}, {tensor2});
    opLogPtr.emplace_back(&copyin1); // index 0
    auto& copyin2 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {tensor4}, {tensor5});
    opLogPtr.emplace_back(&copyin2); // index 1 - moved before cast to satisfy AdjustOpDep conditions
    auto& cast = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor2}, {tensor3});
    opLogPtr.emplace_back(&cast); // index 2
}

TEST_F(InsertSyncTest, TestHandleEventID)
{
    auto rootFuncPtr = std::make_shared<Function>(Program::GetInstance(), "TestHandleEventID", "TestHandleEventID",
                                                  nullptr);
    rootFuncPtr->rootFunc_ = rootFuncPtr.get();
    auto currFunctionPtr = std::make_shared<Function>(Program::GetInstance(), "TestHandleEventIDLeaf",
                                                      "TestHandleEventIDLeaf", rootFuncPtr.get());
    EXPECT_TRUE(currFunctionPtr != nullptr);
    rootFuncPtr->rootFunc_->programs_.emplace(currFunctionPtr->GetFuncMagic(), currFunctionPtr.get());

    std::vector<Operation*> opLogPtr;
    AddOpForTestHandleEventID(opLogPtr, currFunctionPtr);

    PipeSync ps;
    ps.InitIssueQueue(); // Initialize issueState_ before BuildDeps
    DataDependencySearcher dataDependencySearcher;
    ProcessOpList(ps, dataDependencySearcher, opLogPtr);
    std::vector<IndexOp> synced;
    BuildDeps(ps, dataDependencySearcher, opLogPtr, synced);
    // After reorder: copyin1(0), copyin2(1), cast(2)
    EXPECT_EQ(ps.depOps_[0].setPipe[0], static_cast<size_t>(IS_NUM2));  // copyin1 sets for cast
    EXPECT_EQ(ps.depOps_[IS_NUM2].waitPipe[0], static_cast<size_t>(0)); // cast waits for copyin1

    // HandleEventID - Test AdjustOpDep path
    // Set up conditions to trigger AdjustOpDep:
    // 1. currIssueNum >= maxIssueNum (both set to 8)
    // 2. deadlock = true
    // 3. issueQ has enough elements for nextOp
    bool eventIdDeadlock = true;
    bool res = false;
    PipeSync::IssueNum issuenum;
    // issueState_[4] is AIV0_MTE2 queue, contains copyin1(0) and copyin2(1)
    PipeSync::IssueQueue& issueQ = ps.issueState_[IS_NUM4];
    PipeSync::DepOp& handleOp = ps.depOps_[0];    // copyin1
    PipeSync::DepOp& eleOp = ps.depOps_[IS_NUM2]; // cast
    PipeSync::PipeCoreRealEx currPipeCoreEx(handleOp.selfPipeCore.pipeEnd, handleOp.selfPipeCore.core,
                                            handleOp.selfPipeCore.aivCore);
    PipeSync::PipeCoreRealEx elePipeCoreEx(eleOp.selfPipeCore.pipeStart, eleOp.selfPipeCore.core,
                                           eleOp.selfPipeCore.aivCore);
    PipeSync::PipePairEx pp{currPipeCoreEx, elePipeCoreEx};

    // Pre-set issuenum to trigger AdjustOpDep: currIssueNum >= maxIssueNum
    issuenum.maxIssueNum[pp] = IS_NUM8;
    issuenum.currIssueNum[pp] = IS_NUM8;

    // Verify initial state before HandleEventID
    EXPECT_EQ(ps.depOps_[IS_NUM2].waitPipe[0], static_cast<size_t>(0)); // cast waits for copyin1
    EXPECT_EQ(ps.depOps_[0].setPipe[0], static_cast<size_t>(IS_NUM2));  // copyin1 sets for cast

    ps.HandleEventID(handleOp, issueQ, issuenum, eventIdDeadlock, res, synced);
    issueQ.DumpIssueQueue(ps.oriOpList_);
    ps.DumpLatestPipeDepMap();

    // After HandleEventID with AdjustOpDep:
    // RemoveOpDep: copyin1's setPipe removes cast, cast's waitPipe removes copyin1
    // AddOpDep: copyin2's setPipe adds cast, cast's waitPipe adds copyin2
    EXPECT_EQ(ps.depOps_[IS_NUM2].waitPipe[0], static_cast<size_t>(IS_NUM1)); // cast now waits for copyin2
    EXPECT_EQ(ps.depOps_[IS_NUM1].setPipe[0], static_cast<size_t>(IS_NUM2));  // copyin2 sets for cast
    EXPECT_EQ(ps.depOps_[0].setPipe.size(), static_cast<size_t>(0));          // copyin1 has no setPipe

    // InitCVEventIdQ
    ps.InitCVEventIdQ();
    PipeSync::PipeCoreRealEx pcAIC(PIPE_S, CoreType::AIC, AIVCore::UNSPECIFIED);
    PipeSync::PipeCoreRealEx pcAIV1(PIPE_V, CoreType::AIV, AIVCore::AIV1);
    EXPECT_EQ(ps.crossCoreFreeEventId_[pcAIC][0].size(), static_cast<size_t>(IS_NUM16));
    EXPECT_EQ(ps.crossCoreFreeEventId_[pcAIV1][0].size(), static_cast<size_t>(IS_NUM16));
}

TEST_F(InsertSyncTest, TestRelaxFakeDataDep)
{
    auto rootFuncPtr = std::make_shared<Function>(Program::GetInstance(), "TestRelaxFakeDataDep",
                                                  "TestRelaxFakeDataDep", nullptr);
    rootFuncPtr->rootFunc_ = rootFuncPtr.get();
    auto currFunctionPtr = std::make_shared<Function>(Program::GetInstance(), "TestRelaxFakeDataDepLeaf",
                                                      "TestRelaxFakeDataDepLeaf", rootFuncPtr.get());
    EXPECT_TRUE(currFunctionPtr != nullptr);
    rootFuncPtr->rootFunc_->programs_.emplace(currFunctionPtr->GetFuncMagic(), currFunctionPtr.get());

    std::vector<int64_t> shape = {IS_NUM8, IS_NUM8};
    auto tensor1 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor1->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor1->memoryrange.start = IS_NUM100;
    tensor1->memoryrange.end = IS_NUM109;
    auto tensor2 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor2->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor2->memoryrange.start = 0;
    tensor2->memoryrange.end = IS_NUM9;
    auto tensor3 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor3->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor3->memoryrange.start = IS_NUM10;
    tensor3->memoryrange.end = IS_NUM19;
    auto tensor4 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor4->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor4->memoryrange.start = IS_NUM20;
    tensor4->memoryrange.end = IS_NUM29;
    auto tensor5 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor5->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor5->memoryrange.start = IS_NUM30;
    tensor5->memoryrange.end = IS_NUM39;
    auto tensor6 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor6->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor6->memoryrange.start = IS_NUM40;
    tensor6->memoryrange.end = IS_NUM49;
    auto tensor7 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor7->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor7->memoryrange.start = IS_NUM50;
    tensor7->memoryrange.end = IS_NUM59;
    auto tensor8 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor8->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor8->memoryrange.start = IS_NUM60;
    tensor8->memoryrange.end = IS_NUM69;
    auto tensor9 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor9->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor9->memoryrange.start = IS_NUM70;
    tensor9->memoryrange.end = IS_NUM79;
    auto tensor10 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor10->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor10->memoryrange.start = IS_NUM80;
    tensor10->memoryrange.end = IS_NUM89;
    auto tensor11 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor11->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor11->memoryrange.start = IS_NUM90;
    tensor11->memoryrange.end = IS_NUM99;
    auto tensor12 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor12->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor12->memoryrange.start = IS_NUM200;
    tensor12->memoryrange.end = IS_NUM209;
    auto tensor13 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor13->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor13->memoryrange.start = IS_NUM210;
    tensor13->memoryrange.end = IS_NUM219;
    auto tensor14 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor14->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor14->memoryrange.start = IS_NUM220;
    tensor14->memoryrange.end = IS_NUM229;
    auto tensor15 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor15->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor15->memoryrange.start = IS_NUM230;
    tensor15->memoryrange.end = IS_NUM239;
    auto tensor16 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor16->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor16->memoryrange.start = IS_NUM240;
    tensor16->memoryrange.end = IS_NUM249;
    auto tensor17 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor17->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor17->memoryrange.start = IS_NUM250;
    tensor17->memoryrange.end = IS_NUM259;
    auto tensor18 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor18->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor18->memoryrange.start = IS_NUM260;
    tensor18->memoryrange.end = IS_NUM269;
    auto tensor19 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor19->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor19->memoryrange.start = IS_NUM270;
    tensor19->memoryrange.end = IS_NUM279;
    auto tensor20 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor20->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor20->memoryrange.start = IS_NUM280;
    tensor20->memoryrange.end = IS_NUM289;
    auto tensor21 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor21->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor21->memoryrange.start = IS_NUM290;
    tensor21->memoryrange.end = IS_NUM299;
    auto tensor22 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor22->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor22->memoryrange.start = IS_NUM110;
    tensor22->memoryrange.end = IS_NUM119;
    auto tensor23 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor23->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor23->memoryrange.start = IS_NUM120;
    tensor23->memoryrange.end = IS_NUM129;
    auto tensor24 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor24->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor24->memoryrange.start = IS_NUM130;
    tensor24->memoryrange.end = IS_NUM139;
    auto tensor25 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor25->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor25->memoryrange.start = IS_NUM140;
    tensor25->memoryrange.end = IS_NUM149;
    auto tensor26 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor26->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor26->memoryrange.start = IS_NUM150;
    tensor26->memoryrange.end = IS_NUM159;
    auto tensor27 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor27->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor27->memoryrange.start = IS_NUM160;
    tensor27->memoryrange.end = IS_NUM169;
    auto tensor28 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor28->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor28->memoryrange.start = IS_NUM170;
    tensor28->memoryrange.end = IS_NUM179;
    auto tensor29 = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    tensor29->SetMemoryTypeBoth(MemoryType::MEM_UB);
    tensor29->memoryrange.start = IS_NUM180;
    tensor29->memoryrange.end = IS_NUM189;
    std::vector<Operation*> opLogPtr;
    auto& copyin1 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {tensor1}, {tensor2});
    opLogPtr.emplace_back(&copyin1);
    auto& copyin2 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {tensor1}, {tensor3});
    opLogPtr.emplace_back(&copyin2);
    auto& copyin3 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {tensor1}, {tensor4});
    opLogPtr.emplace_back(&copyin3);
    auto& copyin4 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {tensor1}, {tensor5});
    opLogPtr.emplace_back(&copyin4);
    auto& copyin5 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {tensor1}, {tensor6});
    opLogPtr.emplace_back(&copyin5);
    auto& copyin6 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {tensor1}, {tensor7});
    opLogPtr.emplace_back(&copyin6);
    auto& copyin7 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {tensor1}, {tensor8});
    opLogPtr.emplace_back(&copyin7);
    auto& copyin8 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {tensor1}, {tensor9});
    opLogPtr.emplace_back(&copyin8);
    auto& copyin9 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {tensor1}, {tensor10});
    opLogPtr.emplace_back(&copyin9);
    auto& copyin10 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_COPY_IN, {tensor1}, {tensor11});
    opLogPtr.emplace_back(&copyin10);
    auto& cast1 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor1}, {tensor22});
    opLogPtr.emplace_back(&cast1);
    auto& cast2 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor1}, {tensor23});
    opLogPtr.emplace_back(&cast2);
    auto& cast3 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor1}, {tensor24});
    opLogPtr.emplace_back(&cast3);
    auto& cast4 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor1}, {tensor25});
    opLogPtr.emplace_back(&cast4);
    auto& cast5 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor1}, {tensor26});
    opLogPtr.emplace_back(&cast5);
    auto& cast6 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor1}, {tensor27});
    opLogPtr.emplace_back(&cast6);
    auto& cast7 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor1}, {tensor28});
    opLogPtr.emplace_back(&cast7);
    auto& cast8 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor1}, {tensor29});
    opLogPtr.emplace_back(&cast8);
    auto& cast9 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor2}, {tensor12});
    opLogPtr.emplace_back(&cast9);
    auto& cast10 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor3}, {tensor13});
    opLogPtr.emplace_back(&cast10);
    auto& cast11 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor4}, {tensor14});
    opLogPtr.emplace_back(&cast11);
    auto& cast12 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor5}, {tensor15});
    opLogPtr.emplace_back(&cast12);
    auto& cast13 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor6}, {tensor16});
    opLogPtr.emplace_back(&cast13);
    auto& cast14 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor7}, {tensor17});
    opLogPtr.emplace_back(&cast14);
    auto& cast15 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor8}, {tensor18});
    opLogPtr.emplace_back(&cast15);
    auto& cast16 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor9}, {tensor19});
    opLogPtr.emplace_back(&cast16);
    auto& cast17 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor10}, {tensor20});
    opLogPtr.emplace_back(&cast17);
    auto& cast18 = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_CAST, {tensor11}, {tensor21});
    opLogPtr.emplace_back(&cast18);

    PipeSync ps;
    DataDependencySearcher dataDependencySearcher;
    ProcessOpList(ps, dataDependencySearcher, opLogPtr);
    std::vector<IndexOp> synced;
    size_t index = UINT64_MAX;
    EXPECT_EQ(ps.InjectSync(*currFunctionPtr, opLogPtr, index, synced), FAILED);
    BuildDeps(ps, dataDependencySearcher, opLogPtr, synced);

    // Issue op
    size_t totalIssued = 0;
    size_t allIssued = 0;
    for (int i = 0; i < static_cast<int>(PipeSeq::PIPE_END); i++) {
        allIssued += ps.issueState_[i].ops.size();
    }
    bool eventIdDeadlock = false;
    uint64_t eventIdDeadlockEnterTimes = 0;

    while (totalIssued < allIssued) {
        size_t issued = 0;
        size_t issuedTest = IS_NUM100;
        for (int i = 0; i < static_cast<int>(PipeSeq::PIPE_END); i++) {
            std::vector<size_t> issuedOps;
            ps.PopFromQueue(ps.issueState_[i], issuedOps, eventIdDeadlock, synced);
            issued += issuedOps.size();
            if (i == IS_NUM4) {
                issuedTest = issuedOps.size();
            }
            for (auto idx : issuedOps) {
                ps.InjectSync(*currFunctionPtr, opLogPtr, idx, synced);
            }
            if (issuedTest == static_cast<size_t>(0)) {
                break;
            }
        }
        totalIssued += issued;
        // eventIdDeadlockEnterTimes eventIdDeadlock syncedOpLog
        if (issuedTest == static_cast<size_t>(0)) {
            EXPECT_EQ(ps.depOps_[0].setPipe[0], static_cast<size_t>(IS_NUM18));
            EXPECT_EQ(ps.depOps_[IS_NUM1].setPipe[0], static_cast<size_t>(IS_NUM19));
            ps.ProcessDeadLock(eventIdDeadlockEnterTimes, eventIdDeadlock, synced);
            EXPECT_EQ(ps.depOps_[IS_NUM1].setPipe[0], static_cast<size_t>(IS_NUM18));
            continue;
        }
        eventIdDeadlock = false;
        eventIdDeadlockEnterTimes = static_cast<size_t>(0);
        break;
    }
}

TEST_F(InsertSyncTest, TestGetDepInfoSizeMismatch)
{
    PipeSync ps;
    std::vector<IndexOp> emptySyncedOpLog;
    auto pipePair = PipeSync::dataDepPair[0];
    PipeSync::DataDepInfo depInfo;
    EXPECT_EQ(ps.GetDepInfo(emptySyncedOpLog, pipePair, depInfo), FAILED);
    EXPECT_EQ(ps.PipeSeqName(PipeSeq::AIV0_MTE2), "AIV0_MTE2");
    EXPECT_EQ(ps.PipeSeqName(PipeSeq::AIV1_MTE2), "AIV1_MTE2");
    EXPECT_EQ(ps.PipeSeqName(PipeSeq::AIV0_V), "AIV0_V");
    EXPECT_EQ(ps.PipeSeqName(PipeSeq::AIV1_V), "AIV1_V");
    EXPECT_EQ(ps.PipeSeqName(PipeSeq::AIV0_MTE3), "AIV0_MTE3");
    EXPECT_EQ(ps.PipeSeqName(PipeSeq::AIV1_MTE3), "AIV1_MTE3");
    EXPECT_EQ(ps.PipeSeqName(PipeSeq::AIV0_S), "AIV0_S");
    EXPECT_EQ(ps.PipeSeqName(PipeSeq::AIV1_S), "AIV1_S");
}

TEST_F(InsertSyncTest, TestRecycleCrossCoreEventIds)
{
    PipeSync ps;
    ps.InitCVEventIdQ();

    // 场景1: currPipeRealEx 不在 crossCoreFreeEventId_ 中 -> 返回 FAILED
    PipeSync::PipeCoreRealEx notExistPipe(PIPE_V, CoreType::AIV, AIVCore::UNSPECIFIED);
    EXPECT_EQ(ps.RecycleCrossCoreEventIds(notExistPipe), FAILED);

    using CoreDetail = PipeSync::CoreTypeDetail;
    auto makeEr = [](int id, CoreDetail src, CoreDetail dst) {
        return PipeSync::EventResource{id, src, dst, PIPE_S, PIPE_V};
    };
    CoreDetail aicCore{CoreType::AIC, AIVCore::UNSPECIFIED};
    CoreDetail aiv0Core{CoreType::AIV, AIVCore::AIV0};
    CoreDetail aiv1Core{CoreType::AIV, AIVCore::AIV1};

    // 场景2: AIC core - 覆盖 srcCore==dstCore(continue) + eventId<16(queue0) + eventId>=16(queue1)
    PipeSync::PipeCoreRealEx pcAIC(PIPE_S, CoreType::AIC, AIVCore::UNSPECIFIED);
    ps.syncArriveStatus[pcAIC].clear();
    ps.crossCoreFreeEventId_[pcAIC][0].clear();
    ps.crossCoreFreeEventId_[pcAIC][1].clear();
    ps.syncArriveStatus[pcAIC].insert(makeEr(IS_NUM5, aicCore, aicCore));   // srcCore==dstCore -> continue
    ps.syncArriveStatus[pcAIC].insert(makeEr(IS_NUM3, aicCore, aiv0Core));  // eventId<16 -> queue0
    ps.syncArriveStatus[pcAIC].insert(makeEr(IS_NUM20, aicCore, aiv1Core)); // eventId>=16 -> queue1
    EXPECT_EQ(ps.RecycleCrossCoreEventIds(pcAIC), SUCCESS);
    EXPECT_EQ(ps.crossCoreFreeEventId_[pcAIC][0].size(), static_cast<size_t>(IS_NUM1));
    EXPECT_EQ(ps.crossCoreFreeEventId_[pcAIC][0].front(), IS_NUM3);
    EXPECT_EQ(ps.crossCoreFreeEventId_[pcAIC][1].size(), static_cast<size_t>(IS_NUM1));
    EXPECT_EQ(ps.crossCoreFreeEventId_[pcAIC][1].front(), IS_NUM20);

    // 场景3: AIV0 core - 覆盖 eventId<16(queue0) + eventId>=16(跳过)
    PipeSync::PipeCoreRealEx pcAIV0(PIPE_S, CoreType::AIV, AIVCore::AIV0);
    ps.syncArriveStatus[pcAIV0].clear();
    ps.crossCoreFreeEventId_[pcAIV0][0].clear();
    ps.syncArriveStatus[pcAIV0].insert(makeEr(IS_NUM9, aicCore, aiv0Core));  // eventId<16 -> queue0
    ps.syncArriveStatus[pcAIV0].insert(makeEr(IS_NUM29, aicCore, aiv0Core)); // eventId>=16 -> 跳过
    EXPECT_EQ(ps.RecycleCrossCoreEventIds(pcAIV0), SUCCESS);
    EXPECT_EQ(ps.crossCoreFreeEventId_[pcAIV0][0].size(), static_cast<size_t>(IS_NUM1));
    EXPECT_EQ(ps.crossCoreFreeEventId_[pcAIV0][0].front(), IS_NUM9);

    // 场景4: AIV1 core - 覆盖 eventId>=16(queue0) + eventId<16(跳过)
    PipeSync::PipeCoreRealEx pcAIV1(PIPE_S, CoreType::AIV, AIVCore::AIV1);
    ps.syncArriveStatus[pcAIV1].clear();
    ps.crossCoreFreeEventId_[pcAIV1][0].clear();
    ps.syncArriveStatus[pcAIV1].insert(makeEr(IS_NUM30, aicCore, aiv1Core)); // eventId>=16 -> queue0
    ps.syncArriveStatus[pcAIV1].insert(makeEr(IS_NUM10, aicCore, aiv1Core)); // eventId<16 -> 跳过
    EXPECT_EQ(ps.RecycleCrossCoreEventIds(pcAIV1), SUCCESS);
    EXPECT_EQ(ps.crossCoreFreeEventId_[pcAIV1][0].size(), static_cast<size_t>(IS_NUM1));
    EXPECT_EQ(ps.crossCoreFreeEventId_[pcAIV1][0].front(), IS_NUM30);
}

// Helper: create root + leaf Function pair for enableDebug tests
static std::pair<std::shared_ptr<Function>, std::shared_ptr<Function>> SetupDebugFunc(const std::string& name)
{
    auto root = std::make_shared<Function>(Program::GetInstance(), name, name, nullptr);
    root->rootFunc_ = root.get();
    auto leaf = std::make_shared<Function>(Program::GetInstance(), name + "Leaf", name + "Leaf", root.get());
    root->rootFunc_->programs_.emplace(leaf->GetFuncMagic(), leaf.get());
    return {root, leaf};
}

// Helper: batch-create N FP32 tensors with given shape
static std::vector<std::shared_ptr<LogicalTensor>> MakeTensors(int n, const std::vector<int64_t>& shape)
{
    std::vector<std::shared_ptr<LogicalTensor>> ts;
    for (int i = 0; i < n; i++) {
        ts.push_back(npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape)));
    }
    return ts;
}

// Helper: verify one sync op's opcode and AIVCore
static void VerifySyncOp(const Operation* op, Opcode expectedOp, AIVCore expectedCore)
{
    EXPECT_EQ(op->GetOpcode(), expectedOp);
    EXPECT_EQ(op->GetAIVCore(), expectedCore);
}

// Helper: verify BAR_ALL inserted between same-coreType ops
static void VerifyBarAll(const std::vector<Operation*>& ops, size_t idx)
{
    VerifySyncOp(ops[idx], Opcode::OP_BAR_ALL, AIVCore::UNSPECIFIED);
}

// 平台架构切换统一使用公共工具 NpuArchScope(见 pass_test_utils.h)

static Operation& CreateAtomicScopeSyncOp(Function& func, Opcode opcode)
{
    std::vector<std::shared_ptr<LogicalTensor>> input;
    std::vector<std::shared_ptr<LogicalTensor>> output;
    Operation& syncOp = IRBuilder().CreateTensorOpStmt(func, opcode, input, output);
    syncOp.syncQueue_ = {PipeType::PIPE_V, PipeType::PIPE_V, CoreType::AIV, CoreType::AIV,
                         IS_NUM1,          AIVCore::AIV0,    AIVCore::AIV0};
    syncOp.SetAIVCore(AIVCore::AIV0);
    return syncOp;
}

static void ExpectOpListEq(const std::vector<Operation*>& actual, const std::vector<Operation*>& expected)
{
    ASSERT_EQ(actual.size(), expected.size());
    for (size_t i = 0; i < expected.size(); ++i) {
        EXPECT_EQ(actual[i], expected[i]) << "Mismatch at index " << i;
    }
}

// Helper: verify full InsertCvSyncOps 12-op sequence, return next index
static size_t VerifyCvSyncOps(const std::vector<Operation*>& ops, size_t i)
{
    // UNSPECIFIED group (ops 1-4)
    VerifySyncOp(ops[i], Opcode::OP_BAR_ALL, AIVCore::UNSPECIFIED);
    VerifySyncOp(ops[i + IS_NUM1], Opcode::OP_FFTS_CROSS_CORE_SYNC, AIVCore::UNSPECIFIED);
    VerifySyncOp(ops[i + IS_NUM2], Opcode::OP_WAIT_FLAG_DEV, AIVCore::UNSPECIFIED);
    VerifySyncOp(ops[i + IS_NUM3], Opcode::OP_BAR_ALL, AIVCore::UNSPECIFIED);
    // AIV0 group (ops 5-8)
    VerifySyncOp(ops[i + IS_NUM4], Opcode::OP_BAR_ALL, AIVCore::AIV0);
    VerifySyncOp(ops[i + IS_NUM5], Opcode::OP_WAIT_FLAG_DEV, AIVCore::AIV0);
    VerifySyncOp(ops[i + IS_NUM6], Opcode::OP_FFTS_CROSS_CORE_SYNC, AIVCore::AIV0);
    VerifySyncOp(ops[i + IS_NUM7], Opcode::OP_BAR_ALL, AIVCore::AIV0);
    // AIV1 group (ops 9-12)
    VerifySyncOp(ops[i + IS_NUM8], Opcode::OP_BAR_ALL, AIVCore::AIV1);
    VerifySyncOp(ops[i + IS_NUM9], Opcode::OP_WAIT_FLAG_DEV, AIVCore::AIV1);
    VerifySyncOp(ops[i + IS_NUM10], Opcode::OP_FFTS_CROSS_CORE_SYNC, AIVCore::AIV1);
    VerifySyncOp(ops[i + IS_NUM11], Opcode::OP_BAR_ALL, AIVCore::AIV1);
    return i + IS_NUM12;
}

// 覆盖 InsertCvPipeAll 全部 3 条分支：
//   ADD(AIV)→CAST(AIV): 同coreType → BAR_ALL
//   CAST(AIV)→A_MUL_B(AIC): 异coreType → InsertCvSyncOps
//   A_MUL_B(AIC)→EXP(AIV): 异coreType → InsertCvSyncOps
//   EXP 是最后一个 op → skip
TEST_F(InsertSyncTest, TestEnableDebugAllPaths)
{
    auto [root, leaf] = SetupDebugFunc("TestDbgAll");
    auto ts = MakeTensors(IS_NUM7, {IS_NUM8, IS_NUM16});
    (void)IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    (void)IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[2]}, {ts[3]});
    (void)IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_A_MUL_B, {ts[3], ts[4], ts[5]}, {ts[6]});
    (void)IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_EXP, {ts[6]}, {ts[0]});
    InsertSync syncPass;
    syncPass.SetEnableDebug(true);
    syncPass.RunOnFunction(*root);
    // 验证 oriOpList
    EXPECT_EQ(leaf->oriOpList.size(), static_cast<size_t>(IS_NUM4));
    // 验证新 op 列表: 4原始 + 1 BAR_ALL + 12 CvSync + 12 CvSync = 29
    auto ops = leaf->Operations(false).DuplicatedOpList();
    EXPECT_EQ(ops.size(), static_cast<size_t>(IS_NUM29));
    size_t idx = 0;
    EXPECT_EQ(ops[idx++]->GetOpcode(), Opcode::OP_ADD);
    VerifyBarAll(ops, idx++);
    EXPECT_EQ(ops[idx++]->GetOpcode(), Opcode::OP_CAST);
    idx = VerifyCvSyncOps(ops, idx);
    EXPECT_EQ(ops[idx++]->GetOpcode(), Opcode::OP_A_MUL_B);
    idx = VerifyCvSyncOps(ops, idx);
    EXPECT_EQ(ops[idx++]->GetOpcode(), Opcode::OP_EXP);
    EXPECT_EQ(idx, static_cast<size_t>(IS_NUM29));
}

// 边界: 单 op 时 i==oriOpList.size()-1 直接 skip，不插入任何 sync op
TEST_F(InsertSyncTest, TestEnableDebugSingleOp)
{
    auto [root, leaf] = SetupDebugFunc("TestDbgSingle");
    auto ts = MakeTensors(IS_NUM2, {IS_NUM8, IS_NUM16});
    (void)IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0]}, {ts[1]});
    InsertSync syncPass;
    syncPass.SetEnableDebug(true);
    syncPass.RunOnFunction(*root);
    EXPECT_EQ(leaf->oriOpList.size(), static_cast<size_t>(IS_NUM1));
    auto ops = leaf->Operations(false).DuplicatedOpList();
    EXPECT_EQ(ops.size(), static_cast<size_t>(IS_NUM1));
    EXPECT_EQ(ops[0]->GetOpcode(), Opcode::OP_ADD);
}

// 全同 coreType(AIV): 每对相邻 op 之间都插入 BAR_ALL
TEST_F(InsertSyncTest, TestEnableDebugAllSameCoreType)
{
    auto [root, leaf] = SetupDebugFunc("TestDbgSame");
    auto ts = MakeTensors(IS_NUM4, {IS_NUM8, IS_NUM16});
    (void)IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    (void)IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[2]}, {ts[3]});
    (void)IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_EXP, {ts[3]}, {ts[0]});
    InsertSync syncPass;
    syncPass.SetEnableDebug(true);
    syncPass.RunOnFunction(*root);
    EXPECT_EQ(leaf->oriOpList.size(), static_cast<size_t>(IS_NUM3));
    // 3 原始 + 2 BAR_ALL = 5
    auto ops = leaf->Operations(false).DuplicatedOpList();
    EXPECT_EQ(ops.size(), static_cast<size_t>(IS_NUM5));
    EXPECT_EQ(ops[0]->GetOpcode(), Opcode::OP_ADD);
    VerifyBarAll(ops, IS_NUM1);
    EXPECT_EQ(ops[IS_NUM2]->GetOpcode(), Opcode::OP_CAST);
    VerifyBarAll(ops, IS_NUM3);
    EXPECT_EQ(ops[IS_NUM4]->GetOpcode(), Opcode::OP_EXP);
}

// 按真实场景 mla_prolog_quant Unroll128 的 kr_cache 量化写回构造计算图
// (dump: op[38965/38968/38971/38974]):
//   incast b0/b1 --COPY_IN--> cin_i --ADD--> add_i(各路量化结果src)
//   incast kr_idx --COPY_IN--> idx_i(各路散写索引)
//   incast kr_cache 直连 INDEX_OUTCAST 第3输入, 4 路共享并共写 kr_cache_out(outcast, WAW)
// kr_cache_out 与 kr_cache 原地读改写(对照真实 dump: 3901/3943 的 mem_id 同为 3636)
static void BuildKrCacheWritebackGraph(ComputationalGraphBuilder& subGraph)
{
    std::vector<std::string> tensorNames{"b0",   "b1",   "cin0",   "cin1",     "cin2",        "cin3",
                                         "add0", "add1", "add2",   "add3",     "idx0",        "idx1",
                                         "idx2", "idx3", "kr_idx", "kr_cache", "kr_cache_out"};
    std::vector<MemoryType> memTypes{
        MemoryType::MEM_DEVICE_DDR, // b0 (incast)
        MemoryType::MEM_DEVICE_DDR, // b1 (incast)
        MemoryType::MEM_UB,         // cin0
        MemoryType::MEM_UB,         // cin1
        MemoryType::MEM_UB,         // cin2
        MemoryType::MEM_UB,         // cin3
        MemoryType::MEM_UB,         // add0
        MemoryType::MEM_UB,         // add1
        MemoryType::MEM_UB,         // add2
        MemoryType::MEM_UB,         // add3
        MemoryType::MEM_UB,         // idx0
        MemoryType::MEM_UB,         // idx1
        MemoryType::MEM_UB,         // idx2
        MemoryType::MEM_UB,         // idx3
        MemoryType::MEM_DEVICE_DDR, // kr_idx (incast)
        MemoryType::MEM_DEVICE_DDR, // kr_cache (incast)
        MemoryType::MEM_DEVICE_DDR, // kr_cache_out (outcast)
    };
    EXPECT_EQ(subGraph.AddTensors(DataType::DT_FP32, {256, 256}, memTypes, tensorNames, 0), true);
    std::vector<Opcode> opCodes{
        Opcode::OP_COPY_IN,       Opcode::OP_COPY_IN,       Opcode::OP_COPY_IN,       Opcode::OP_COPY_IN,
        Opcode::OP_ADD,           Opcode::OP_ADD,           Opcode::OP_ADD,           Opcode::OP_ADD,
        Opcode::OP_COPY_IN,       Opcode::OP_COPY_IN,       Opcode::OP_COPY_IN,       Opcode::OP_COPY_IN,
        Opcode::OP_INDEX_OUTCAST, Opcode::OP_INDEX_OUTCAST, Opcode::OP_INDEX_OUTCAST, Opcode::OP_INDEX_OUTCAST};
    std::vector<std::vector<std::string>> ioperands{{"b0"},
                                                    {"b1"},
                                                    {"b0"},
                                                    {"b1"},
                                                    {"cin0", "cin1"},
                                                    {"cin1", "cin2"},
                                                    {"cin2", "cin3"},
                                                    {"cin3", "cin0"},
                                                    {"kr_idx"},
                                                    {"kr_idx"},
                                                    {"kr_idx"},
                                                    {"kr_idx"},
                                                    {"add0", "idx0", "kr_cache"},
                                                    {"add1", "idx1", "kr_cache"},
                                                    {"add2", "idx2", "kr_cache"},
                                                    {"add3", "idx3", "kr_cache"}};
    std::vector<std::vector<std::string>> ooperands{
        {"cin0"}, {"cin1"}, {"cin2"}, {"cin3"}, {"add0"},         {"add1"},         {"add2"},         {"add3"},
        {"idx0"}, {"idx1"}, {"idx2"}, {"idx3"}, {"kr_cache_out"}, {"kr_cache_out"}, {"kr_cache_out"}, {"kr_cache_out"}};
    std::vector<std::string> opNames{"cpin0",    "cpin1",    "cpin2",    "cpin3",   "add0",  "add1",
                                     "add2",     "add3",     "cpin4",    "cpin5",   "cpin6", "cpin7",
                                     "outcast0", "outcast1", "outcast2", "outcast3"};
    EXPECT_EQ(subGraph.AddOps(opCodes, ioperands, ooperands, opNames, true), true);
    auto krCache = subGraph.GetTensor("kr_cache");
    auto krCacheOut = subGraph.GetTensor("kr_cache_out");
    ASSERT_NE(krCache, nullptr);
    ASSERT_NE(krCacheOut, nullptr);
    krCacheOut->memoryrange.memId = krCache->memoryrange.memId;
    EXPECT_EQ(subGraph.SetInCast({"b0", "b1", "kr_idx", "kr_cache"}), true);
    EXPECT_EQ(subGraph.SetOutCast({"kr_cache_out"}), true);
}

// 收集 opLogPtr 中全部 INDEX_OUTCAST 的索引
static std::vector<size_t> CollectOutcastIdxs(const std::vector<Operation*>& opLogPtr)
{
    std::vector<size_t> outcastIdxs;
    for (size_t j = 0; j < opLogPtr.size(); j++) {
        if (opLogPtr[j]->GetOpcode() == Opcode::OP_INDEX_OUTCAST) {
            outcastIdxs.push_back(j);
        }
    }
    return outcastIdxs;
}

// 禁止 AIV0↔AIV1 同步: 按 BuildKrCacheWritebackGraph 的 kr_cache 写回形态构造,
// 相邻路经 kr_cache(WAR, DDR同mem_id) 与 kr_cache_out(WAW) 建立数据依赖后, 被交替分到
// AIV0/AIV1 即触发 InjectWaitFlag 的 AIV0/AIV1 同步拦截, InjectSync 必须传播 FAILED 且不标记 issued
TEST_F(InsertSyncTest, TestInjectSyncFailOnAiv0Aiv1Sync)
{
    auto rootFuncPtr = std::make_shared<Function>(Program::GetInstance(), "TestAiv0Aiv1SyncFail",
                                                  "TestAiv0Aiv1SyncFail", nullptr);
    rootFuncPtr->rootFunc_ = rootFuncPtr.get();
    auto currFunctionPtr = std::make_shared<Function>(Program::GetInstance(), "TestAiv0Aiv1SyncFailLeaf",
                                                      "TestAiv0Aiv1SyncFailLeaf", rootFuncPtr.get());
    ASSERT_TRUE(currFunctionPtr != nullptr);
    rootFuncPtr->rootFunc_->programs_.emplace(currFunctionPtr->GetFuncMagic(), currFunctionPtr.get());

    ComputationalGraphBuilder subGraph;
    BuildKrCacheWritebackGraph(subGraph);
    Function* function = subGraph.GetFunction();
    ASSERT_NE(function, nullptr);

    auto opLogPtr = function->Operations(false).DuplicatedOpList();
    ASSERT_EQ(opLogPtr.size(), static_cast<size_t>(IS_NUM16));
    // 模拟 OoOSchedule 对 4 路 INDEX_OUTCAST 的交替分核结果(AIV0/AIV0/AIV1/AIV1, 对照真实 dump)
    for (size_t i = 0; i < IS_NUM4; i++) {
        auto outcast = subGraph.GetOp("outcast" + std::to_string(i));
        ASSERT_NE(outcast, nullptr);
        outcast->SetAIVCore(i < IS_NUM2 ? AIVCore::AIV0 : AIVCore::AIV1);
    }

    PipeSync ps;
    DataDependencySearcher dataDependencySearcher;
    ProcessOpList(ps, dataDependencySearcher, opLogPtr);
    std::vector<IndexOp> synced;
    BuildDeps(ps, dataDependencySearcher, opLogPtr, synced);
    // 相邻路共写 kr_cache_out(WAW) 且经 kr_cache 构成 WAR(DDR同mem_id), 必须已建立依赖
    auto outcastIdxs = CollectOutcastIdxs(opLogPtr);
    ASSERT_EQ(outcastIdxs.size(), static_cast<size_t>(IS_NUM4));
    EXPECT_GT(ps.depOps_[outcastIdxs[1]].waitPipe.size(), static_cast<size_t>(0));
    // fixture 的 AdjustCopyOpTileCfg 将所有 op 的 aivCore 固定为 AIV0, 此处按模拟的 OoO 分核结果
    // 修正 4 路 INDEX_OUTCAST 在 depOps_ 中的 aivCore(AIV0/AIV0/AIV1/AIV1, 对照真实 dump)
    for (size_t i = 0; i < IS_NUM4; i++) {
        ps.depOps_[outcastIdxs[i]].selfPipeCore.aivCore = (i < IS_NUM2) ? AIVCore::AIV0 : AIVCore::AIV1;
    }
    // outcast2(AIV1) 与其等待的 outcast1(AIV0) 构成 AIV0↔AIV1 跨核依赖, 必须被拦截
    EXPECT_EQ(ps.InjectSync(*currFunctionPtr, opLogPtr, outcastIdxs[2], synced), FAILED);
    EXPECT_FALSE(ps.depOps_[outcastIdxs[2]].issued);
}

// 全同 coreType(AIC): AIC→AIC 同核心场景，BAR_ALL 的 AIVCore 取自 nextOp(AIC 算子)，其值为 UNSPECIFIED
TEST_F(InsertSyncTest, TestEnableDebugAllAic)
{
    auto [root, leaf] = SetupDebugFunc("TestDbgAic");
    auto ts = MakeTensors(IS_NUM10, {IS_NUM8, IS_NUM16});
    (void)IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_A_MUL_B, {ts[0], ts[1], ts[2]}, {ts[3]});
    (void)IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_A_MULACC_B, {ts[3], ts[4], ts[5]}, {ts[6]});
    (void)IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_A_MUL_BT, {ts[6], ts[7], ts[8]}, {ts[9]});
    InsertSync syncPass;
    syncPass.SetEnableDebug(true);
    syncPass.RunOnFunction(*root);
    EXPECT_EQ(leaf->oriOpList.size(), static_cast<size_t>(IS_NUM3));
    // 3 原始 + 2 BAR_ALL = 5
    auto ops = leaf->Operations(false).DuplicatedOpList();
    EXPECT_EQ(ops.size(), static_cast<size_t>(IS_NUM5));
    EXPECT_EQ(ops[0]->GetOpcode(), Opcode::OP_A_MUL_B);
    VerifyBarAll(ops, IS_NUM1);
    EXPECT_EQ(ops[IS_NUM2]->GetOpcode(), Opcode::OP_A_MULACC_B);
    VerifyBarAll(ops, IS_NUM3);
    EXPECT_EQ(ops[IS_NUM4]->GetOpcode(), Opcode::OP_A_MUL_BT);
}

// =========================================================================
// AdjustSyncByAtomicScope 测试用例
// 后处理逻辑：A5 平台上，cluster 内的 wait-like sync 移到 cluster 前，
// set-like sync 移到 cluster 后。非 A5 平台不做处理。
// =========================================================================

// 单条 wait-like 同步（OP_SYNC_DST）被移动到 cluster 前
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeMovesSingleWaitBeforeCluster)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestMoveWaitBeforeCluster");
    (void)root;
    auto ts = MakeTensors(IS_NUM4, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[2]}, {ts[3]});
    auto& wait = CreateAtomicScopeSyncOp(*leaf, Opcode::OP_SYNC_DST);
    add.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    add.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    std::vector<Operation*> opList = {&add, &wait, &cast};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), SUCCESS);

    ExpectOpListEq(opList, {&wait, &add, &cast});
}

// 单条 set-like 同步（OP_SYNC_SRC）被移动到 cluster 后
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeMovesSingleSetAfterCluster)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestMoveSetAfterCluster");
    (void)root;
    auto ts = MakeTensors(IS_NUM4, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[2]}, {ts[3]});
    auto& set = CreateAtomicScopeSyncOp(*leaf, Opcode::OP_SYNC_SRC);
    add.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    add.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    std::vector<Operation*> opList = {&add, &set, &cast};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), SUCCESS);

    ExpectOpListEq(opList, {&add, &cast, &set});
}

// OP_BAR_V 不可移动，出现在 cluster 内时失败
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeRejectsBarVInCluster)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestRejectBarV");
    (void)root;
    auto ts = MakeTensors(IS_NUM4, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[2]}, {ts[3]});
    auto& barV = CreateAtomicScopeSyncOp(*leaf, Opcode::OP_BAR_V);
    add.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    add.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    std::vector<Operation*> opList = {&add, &barV, &cast};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), FAILED);
}

// CV eventId 耗尽兜底 force 序列（BAR_ALL 等）落在 cluster 内时，该 cluster 整体不再调整 op 顺序
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeSkipsForceSyncOps)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestSkipForceSyncOps");
    (void)root;
    auto ts = MakeTensors(IS_NUM4, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[2]}, {ts[3]});
    // force 序列前的 set（先被收集，遇到 force op 后整体清空）与 force 序列后的 wait 均保持原位
    Operation& cvSet = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CV_SYNC_SRC, {}, {});
    cvSet.syncQueue_ = {PipeType::PIPE_M, PipeType::PIPE_V, CoreType::AIC, CoreType::AIV,
                        IS_NUM2,          AIVCore::AIV0,    AIVCore::AIV1};
    cvSet.SetAIVCore(AIVCore::AIV0);
    auto& barAll = CreateAtomicScopeSyncOp(*leaf, Opcode::OP_BAR_ALL);
    auto& wait = CreateAtomicScopeSyncOp(*leaf, Opcode::OP_SYNC_DST);
    add.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    add.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    std::vector<Operation*> opList = {&add, &cvSet, &barAll, &wait, &cast};

    InsertSync syncPass;
    std::unordered_set<Operation*> forceSyncOps = {&barAll};
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, forceSyncOps), SUCCESS);

    // cluster 整体不调整：所有 op 保持原位
    ExpectOpListEq(opList, {&add, &cvSet, &barAll, &wait, &cast});
}

// 非 force 序列的 immovable sync（BAR_ALL）落在同核 cluster 内时报错
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeRejectsBarAllInCluster)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestRejectBarAll");
    (void)root;
    auto ts = MakeTensors(IS_NUM4, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[2]}, {ts[3]});
    auto& barAll = CreateAtomicScopeSyncOp(*leaf, Opcode::OP_BAR_ALL);
    add.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    add.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    std::vector<Operation*> opList = {&add, &barAll, &cast};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), FAILED);
}

// cluster 内连续 sync op（不配对）允许移动，各自移到对应边界
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeMovesConsecutiveUnpairedSyncOps)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestConsecutiveSync");
    (void)root;
    auto ts = MakeTensors(IS_NUM5, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& midExp = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_EXP, {ts[2]}, {ts[3]});
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[3]}, {ts[4]});
    // wait 和 set 连续出现（中间无 cluster op 隔开），但 eventId 不同，不配对
    std::vector<std::shared_ptr<LogicalTensor>> emptyInput;
    std::vector<std::shared_ptr<LogicalTensor>> emptyOutput;
    Operation& wait = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SYNC_DST, emptyInput, emptyOutput);
    wait.syncQueue_ = {PipeType::PIPE_MTE2, PipeType::PIPE_V, CoreType::AIV, CoreType::AIV, IS_NUM1,
                       AIVCore::AIV0,       AIVCore::AIV0};
    wait.SetAIVCore(AIVCore::AIV0);
    Operation& set = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SYNC_SRC, emptyInput, emptyOutput);
    set.syncQueue_ = {PipeType::PIPE_V, PipeType::PIPE_MTE3, CoreType::AIV, CoreType::AIV,
                      IS_NUM2,          AIVCore::AIV0,       AIVCore::AIV0};
    set.SetAIVCore(AIVCore::AIV0);
    add.SetAtomicScopeId(VF_SCOPE_A);
    midExp.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    add.SetAIVCore(AIVCore::AIV0);
    midExp.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    // wait 和 set 连续，但 eventId 不同（1 vs 2），pipe 也不配对
    std::vector<Operation*> opList = {&add, &wait, &set, &midExp, &cast};

    // wait 移到 cluster 前，set 移到 cluster 后
    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), SUCCESS);
    ExpectOpListEq(opList, {&wait, &add, &midExp, &cast, &set});
}

// 反向 pipe 对复用同一 eventId（V->MTE2 set 与 MTE2->V wait）是两个无关事件，不构成配对，允许调整
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeAllowsOppositeDirectionSameEventId)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestAllowOppositeDirection");
    (void)root;
    auto ts = MakeTensors(IS_NUM5, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& midExp = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_EXP, {ts[2]}, {ts[3]});
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[3]}, {ts[4]});
    // set: V->MTE2, eventId=6（V 产出通知 MTE2 搬运）
    // wait: MTE2->V, eventId=6（V 等 MTE2 搬运就绪）—— 反向对独立分配 eventid，数值相同只是复用
    std::vector<std::shared_ptr<LogicalTensor>> emptyInput;
    std::vector<std::shared_ptr<LogicalTensor>> emptyOutput;
    Operation& set = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SYNC_SRC, emptyInput, emptyOutput);
    set.syncQueue_ = {PipeType::PIPE_V, PipeType::PIPE_MTE2, CoreType::AIV, CoreType::AIV,
                      IS_NUM6,          AIVCore::AIV0,       AIVCore::AIV0};
    set.SetAIVCore(AIVCore::AIV0);
    Operation& wait = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SYNC_DST, emptyInput, emptyOutput);
    wait.syncQueue_ = {PipeType::PIPE_MTE2, PipeType::PIPE_V, CoreType::AIV, CoreType::AIV, IS_NUM6,
                       AIVCore::AIV0,       AIVCore::AIV0};
    wait.SetAIVCore(AIVCore::AIV0);
    add.SetAtomicScopeId(VF_SCOPE_A);
    midExp.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    add.SetAIVCore(AIVCore::AIV0);
    midExp.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    std::vector<Operation*> opList = {&add, &set, &midExp, &wait, &cast};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), SUCCESS);
    ExpectOpListEq(opList, {&wait, &add, &midExp, &cast, &set});
}

// cluster 内的核间同步 set（OP_CV_SYNC_SRC）可移动，移到 cluster 后
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeMovesCvSetAfterCluster)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestMoveCvSetAfterCluster");
    (void)root;
    auto ts = MakeTensors(IS_NUM4, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[2]}, {ts[3]});
    // 跨核 CV set: AIV0 上执行 set(AIC PIPE_M 数据就绪) 通知 AIV1 wait(PIPE_V), eventId=1
    std::vector<std::shared_ptr<LogicalTensor>> emptyInput;
    std::vector<std::shared_ptr<LogicalTensor>> emptyOutput;
    Operation& cvSet = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CV_SYNC_SRC, emptyInput, emptyOutput);
    cvSet.syncQueue_ = {PipeType::PIPE_M, PipeType::PIPE_V, CoreType::AIC, CoreType::AIV,
                        IS_NUM1,          AIVCore::AIV0,    AIVCore::AIV1};
    cvSet.SetAIVCore(AIVCore::AIV0);
    add.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    add.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    std::vector<Operation*> opList = {&add, &cvSet, &cast};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), SUCCESS);

    ExpectOpListEq(opList, {&add, &cast, &cvSet});
}

// cluster 内的核间同步 wait（OP_CV_SYNC_DST）可移动，移到 cluster 前
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeMovesCvWaitBeforeCluster)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestMoveCvWaitBeforeCluster");
    (void)root;
    auto ts = MakeTensors(IS_NUM4, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[2]}, {ts[3]});
    // 跨核 CV wait: AIV0 上等待 AIC 的 set, eventId=1
    std::vector<std::shared_ptr<LogicalTensor>> emptyInput;
    std::vector<std::shared_ptr<LogicalTensor>> emptyOutput;
    Operation& cvWait = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CV_SYNC_DST, emptyInput, emptyOutput);
    cvWait.syncQueue_ = {PipeType::PIPE_M, PipeType::PIPE_V,     CoreType::AIC, CoreType::AIV,
                         IS_NUM1,          AIVCore::UNSPECIFIED, AIVCore::AIV0};
    cvWait.SetAIVCore(AIVCore::AIV0);
    add.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    add.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    std::vector<Operation*> opList = {&add, &cvWait, &cast};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), SUCCESS);

    ExpectOpListEq(opList, {&cvWait, &add, &cast});
}

// 同一 cluster 内收集到相同 eventId 的 CV set 与 CV wait（AIV0->AIC 的 set 与 AIC->AIV0 的
// wait，双向握手共享 eventId 数值空间且复用后数值相同，两端均在本核执行）：若按边界挪动
// （wait 移前、set 移后），与窗口内原位的异核配对端 op 形成顺序颠倒（V set C wait C set V wait
// -> V wait C wait C set V set）互等死锁，须报错拒绝
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeRejectsPairedCvSetWaitInSameCluster)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestRejectPairedCvSetWait");
    (void)root;
    auto ts = MakeTensors(IS_NUM5, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& midExp = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_EXP, {ts[2]}, {ts[3]});
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[3]}, {ts[4]});
    // CV set: AIV0->AIC 握手，AIV0 执行, eventId=3
    // CV wait: AIC->AIV0 握手，AIV0 执行, eventId=3 —— 双向握手 eventId 数值撞车
    std::vector<std::shared_ptr<LogicalTensor>> emptyInput;
    std::vector<std::shared_ptr<LogicalTensor>> emptyOutput;
    Operation& cvSet = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CV_SYNC_SRC, emptyInput, emptyOutput);
    cvSet.syncQueue_ = {PipeType::PIPE_V, PipeType::PIPE_FIX, CoreType::AIV,       CoreType::AIC,
                        IS_NUM3,          AIVCore::AIV0,      AIVCore::UNSPECIFIED};
    cvSet.SetAIVCore(AIVCore::AIV0);
    Operation& cvWait = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CV_SYNC_DST, emptyInput, emptyOutput);
    cvWait.syncQueue_ = {PipeType::PIPE_FIX,   PipeType::PIPE_V, CoreType::AIC, CoreType::AIV, IS_NUM3,
                         AIVCore::UNSPECIFIED, AIVCore::AIV0};
    cvWait.SetAIVCore(AIVCore::AIV0);
    add.SetAtomicScopeId(VF_SCOPE_A);
    midExp.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    add.SetAIVCore(AIVCore::AIV0);
    midExp.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    std::vector<Operation*> opList = {&add, &cvSet, &midExp, &cvWait, &cast};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), FAILED);
}

// 同一 cluster 内先 wait 后 set 的 CV 同步（相同 eventId）不报错，wait 移前 set 移后，相对顺序保持
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeMovesCvWaitBeforeSetInSameCluster)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestMoveCvWaitBeforeSet");
    (void)root;
    auto ts = MakeTensors(IS_NUM5, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& midExp = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_EXP, {ts[2]}, {ts[3]});
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[3]}, {ts[4]});
    // CV wait 与 CV set 相同 eventId=3，wait 在前，移动后仍保持 wait 在 set 前
    std::vector<std::shared_ptr<LogicalTensor>> emptyInput;
    std::vector<std::shared_ptr<LogicalTensor>> emptyOutput;
    Operation& cvWait = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CV_SYNC_DST, emptyInput, emptyOutput);
    cvWait.syncQueue_ = {PipeType::PIPE_M, PipeType::PIPE_V, CoreType::AIC, CoreType::AIV,
                         IS_NUM3,          AIVCore::AIV0,    AIVCore::AIV1};
    cvWait.SetAIVCore(AIVCore::AIV0);
    Operation& cvSet = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CV_SYNC_SRC, emptyInput, emptyOutput);
    cvSet.syncQueue_ = {PipeType::PIPE_M, PipeType::PIPE_V, CoreType::AIC, CoreType::AIV,
                        IS_NUM3,          AIVCore::AIV0,    AIVCore::AIV1};
    cvSet.SetAIVCore(AIVCore::AIV0);
    add.SetAtomicScopeId(VF_SCOPE_A);
    midExp.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    add.SetAIVCore(AIVCore::AIV0);
    midExp.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    std::vector<Operation*> opList = {&add, &cvWait, &midExp, &cvSet, &cast};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), SUCCESS);

    ExpectOpListEq(opList, {&cvWait, &add, &midExp, &cast, &cvSet});
}

// cluster 内 CV set/wait eventId 不同，不配对，各自移动
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeMovesUnpairedCvSetAndWaitIndependently)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestMoveUnpairedCvSetWait");
    (void)root;
    auto ts = MakeTensors(IS_NUM5, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& midExp = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_EXP, {ts[2]}, {ts[3]});
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[3]}, {ts[4]});
    // CV set eventId=3, CV wait eventId=5，各自独立移动
    std::vector<std::shared_ptr<LogicalTensor>> emptyInput;
    std::vector<std::shared_ptr<LogicalTensor>> emptyOutput;
    Operation& cvSet = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CV_SYNC_SRC, emptyInput, emptyOutput);
    cvSet.syncQueue_ = {PipeType::PIPE_M, PipeType::PIPE_V, CoreType::AIC, CoreType::AIV,
                        IS_NUM3,          AIVCore::AIV0,    AIVCore::AIV1};
    cvSet.SetAIVCore(AIVCore::AIV0);
    Operation& cvWait = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CV_SYNC_DST, emptyInput, emptyOutput);
    cvWait.syncQueue_ = {PipeType::PIPE_M, PipeType::PIPE_V, CoreType::AIC, CoreType::AIV,
                         IS_NUM5,          AIVCore::AIV0,    AIVCore::AIV1};
    cvWait.SetAIVCore(AIVCore::AIV0);
    add.SetAtomicScopeId(VF_SCOPE_A);
    midExp.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    add.SetAIVCore(AIVCore::AIV0);
    midExp.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    std::vector<Operation*> opList = {&add, &cvSet, &midExp, &cvWait, &cast};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), SUCCESS);

    ExpectOpListEq(opList, {&cvWait, &add, &midExp, &cast, &cvSet});
}

// CV 同步与普通同步 eventId 相同时不跨域配对，各自移动
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeCvAndRegularSyncSameEventIdNoPairing)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestCvRegularSameEventId");
    (void)root;
    auto ts = MakeTensors(IS_NUM5, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& midExp = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_EXP, {ts[2]}, {ts[3]});
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[3]}, {ts[4]});
    // CV set eventId=3 与普通 wait(OP_SYNC_DST) eventId=3，跨域不配对
    std::vector<std::shared_ptr<LogicalTensor>> emptyInput;
    std::vector<std::shared_ptr<LogicalTensor>> emptyOutput;
    Operation& cvSet = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CV_SYNC_SRC, emptyInput, emptyOutput);
    cvSet.syncQueue_ = {PipeType::PIPE_M, PipeType::PIPE_V, CoreType::AIC, CoreType::AIV,
                        IS_NUM3,          AIVCore::AIV0,    AIVCore::AIV1};
    cvSet.SetAIVCore(AIVCore::AIV0);
    Operation& wait = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SYNC_DST, emptyInput, emptyOutput);
    wait.syncQueue_ = {PipeType::PIPE_MTE2, PipeType::PIPE_V, CoreType::AIV, CoreType::AIV, IS_NUM3,
                       AIVCore::AIV0,       AIVCore::AIV0};
    wait.SetAIVCore(AIVCore::AIV0);
    add.SetAtomicScopeId(VF_SCOPE_A);
    midExp.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    add.SetAIVCore(AIVCore::AIV0);
    midExp.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    std::vector<Operation*> opList = {&add, &cvSet, &midExp, &wait, &cast};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), SUCCESS);

    ExpectOpListEq(opList, {&wait, &add, &midExp, &cast, &cvSet});
}

// 非 A5 平台不做后处理
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeNoopsOnNonA5)
{
    NpuArchScope scopedArch(NPUArch::DAV_2201);
    auto [root, leaf] = SetupDebugFunc("TestNoopNonA5");
    (void)root;
    auto ts = MakeTensors(IS_NUM4, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[2]}, {ts[3]});
    auto& wait = CreateAtomicScopeSyncOp(*leaf, Opcode::OP_SYNC_DST);
    add.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    std::vector<Operation*> opList = {&add, &wait, &cast};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), SUCCESS);

    ExpectOpListEq(opList, {&add, &wait, &cast});
}

// 同一 cluster 内出现配对的 set/wait（同一 (setPipe, waitPipe, eventId) 三元组）时失败
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeRejectsPairedSetWaitInSameCluster)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestRejectPairedSetWait");
    (void)root;
    auto ts = MakeTensors(IS_NUM5, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& midExp = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_EXP, {ts[2]}, {ts[3]});
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[3]}, {ts[4]});
    // 同一对 set/wait: 两端 syncQueue_ 均按 {set.pipe, wait.pipe} 构造 (GenSyncOp),
    // codegen 生成 set_flag(V, MTE2, 3) / wait_flag(V, MTE2, 3), 三元组完全一致
    std::vector<std::shared_ptr<LogicalTensor>> emptyInput;
    std::vector<std::shared_ptr<LogicalTensor>> emptyOutput;
    Operation& setOp = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SYNC_SRC, emptyInput, emptyOutput);
    setOp.syncQueue_ = {PipeType::PIPE_V, PipeType::PIPE_MTE2, CoreType::AIV, CoreType::AIV,
                        IS_NUM3,          AIVCore::AIV0,       AIVCore::AIV0};
    setOp.SetAIVCore(AIVCore::AIV0);
    Operation& waitOp = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SYNC_DST, emptyInput, emptyOutput);
    waitOp.syncQueue_ = {PipeType::PIPE_V, PipeType::PIPE_MTE2, CoreType::AIV, CoreType::AIV,
                         IS_NUM3,          AIVCore::AIV0,       AIVCore::AIV0};
    waitOp.SetAIVCore(AIVCore::AIV0);
    add.SetAtomicScopeId(VF_SCOPE_A);
    midExp.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    add.SetAIVCore(AIVCore::AIV0);
    midExp.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    // set 和 wait 都在 cluster 内部，中间有 midExp 隔开，各自 run length = 1
    std::vector<Operation*> opList = {&add, &setOp, &midExp, &waitOp, &cast};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), FAILED);
}

// cluster 内同时出现不配对的 set 和 wait（不同 eventId），各自移动到两侧，不报错
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeMovesUnpairedSetAndWaitIndependently)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestMoveUnpairedSetWait");
    (void)root;
    auto ts = MakeTensors(IS_NUM5, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& midExp = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_EXP, {ts[2]}, {ts[3]});
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[3]}, {ts[4]});
    // set: eventId=3, pipeId_=PIPE_V, trigPipeId_=PIPE_MTE2
    // wait: eventId=5, pipeId_=PIPE_MTE3, trigPipeId_=PIPE_V
    // eventId 不同 → 不配对 → 各自移动
    std::vector<std::shared_ptr<LogicalTensor>> emptyInput;
    std::vector<std::shared_ptr<LogicalTensor>> emptyOutput;
    Operation& setOp = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SYNC_SRC, emptyInput, emptyOutput);
    setOp.syncQueue_ = {PipeType::PIPE_V, PipeType::PIPE_MTE2, CoreType::AIV, CoreType::AIV,
                        IS_NUM3,          AIVCore::AIV0,       AIVCore::AIV0};
    setOp.SetAIVCore(AIVCore::AIV0);
    Operation& waitOp = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SYNC_DST, emptyInput, emptyOutput);
    waitOp.syncQueue_ = {PipeType::PIPE_MTE3, PipeType::PIPE_V, CoreType::AIV, CoreType::AIV, IS_NUM5,
                         AIVCore::AIV0,       AIVCore::AIV0};
    waitOp.SetAIVCore(AIVCore::AIV0);
    add.SetAtomicScopeId(VF_SCOPE_A);
    midExp.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    add.SetAIVCore(AIVCore::AIV0);
    midExp.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    // set 和 wait 都在 cluster 内部，中间有 midExp 隔开
    std::vector<Operation*> opList = {&add, &setOp, &midExp, &waitOp, &cast};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), SUCCESS);

    // wait 移到 cluster 前，set 移到 cluster 后
    ExpectOpListEq(opList, {&waitOp, &add, &midExp, &cast, &setOp});
}

// 多个 cluster 各自独立处理，互不干扰
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeHandlesMultipleClustersIndependently)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestMultiCluster");
    (void)root;
    auto ts = MakeTensors(IS_NUM8, {IS_NUM8, IS_NUM16});
    // cluster A: add, cast (atomicScopeId=7)
    // cluster B: exp, sqrt (atomicScopeId=8)
    // 中间有一个非 cluster op: neg
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& waitA = CreateAtomicScopeSyncOp(*leaf, Opcode::OP_SYNC_DST);
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[2]}, {ts[3]});
    auto& neg = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_NEG, {ts[3]}, {ts[4]});
    auto& setB = CreateAtomicScopeSyncOp(*leaf, Opcode::OP_SYNC_SRC);
    auto& exp = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_EXP, {ts[4]}, {ts[5]});
    auto& sqrt = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SQRT, {ts[5]}, {ts[6]});
    add.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    exp.SetAtomicScopeId(VF_SCOPE_B);
    sqrt.SetAtomicScopeId(VF_SCOPE_B);
    add.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    exp.SetAIVCore(AIVCore::AIV0);
    sqrt.SetAIVCore(AIVCore::AIV0);
    std::vector<Operation*> opList = {&add, &waitA, &cast, &neg, &exp, &setB, &sqrt};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), SUCCESS);

    // cluster A: waitA 移到 add 前
    // cluster B: setB 移到 sqrt 后
    ExpectOpListEq(opList, {&waitA, &add, &cast, &neg, &exp, &sqrt, &setB});
}

// 无 atomic scope op 时不做任何处理
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeNoopsWithoutAtomicScope)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestNoopNoScope");
    (void)root;
    auto ts = MakeTensors(IS_NUM4, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[2]}, {ts[3]});
    auto& wait = CreateAtomicScopeSyncOp(*leaf, Opcode::OP_SYNC_DST);
    // 不设置 atomicScopeId，默认 -1
    std::vector<Operation*> opList = {&add, &wait, &cast};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), SUCCESS);

    ExpectOpListEq(opList, {&add, &wait, &cast});
}

// 两个相邻 cluster（中间无非 cluster op），各自 set/wait sync 移到各自 cluster 边界
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeHandlesAdjacentClusters)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestAdjacentClusters");
    (void)root;
    auto ts = MakeTensors(IS_NUM8, {IS_NUM8, IS_NUM16});
    // cluster A: add, cast (atomicScopeId=7)，内部有 waitA 和 setA
    // cluster B: exp, sqrt (atomicScopeId=8)，内部有 waitB 和 setB
    // 两个 cluster 直接相邻，中间无非 cluster op
    // 使用不同 eventId 避免跨 cluster 配对检查误触发
    std::vector<std::shared_ptr<LogicalTensor>> emptyInput;
    std::vector<std::shared_ptr<LogicalTensor>> emptyOutput;
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    Operation& waitA = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SYNC_DST, emptyInput, emptyOutput);
    waitA.syncQueue_ = {PipeType::PIPE_MTE2, PipeType::PIPE_V, CoreType::AIV, CoreType::AIV, IS_NUM1,
                        AIVCore::AIV0,       AIVCore::AIV0};
    waitA.SetAIVCore(AIVCore::AIV0);
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[2]}, {ts[3]});
    Operation& setA = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SYNC_SRC, emptyInput, emptyOutput);
    setA.syncQueue_ = {PipeType::PIPE_V, PipeType::PIPE_MTE2, CoreType::AIV, CoreType::AIV,
                       IS_NUM2,          AIVCore::AIV0,       AIVCore::AIV0};
    setA.SetAIVCore(AIVCore::AIV0);
    auto& exp = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_EXP, {ts[3]}, {ts[4]});
    Operation& waitB = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SYNC_DST, emptyInput, emptyOutput);
    waitB.syncQueue_ = {PipeType::PIPE_MTE3, PipeType::PIPE_V, CoreType::AIV, CoreType::AIV, IS_NUM3,
                        AIVCore::AIV0,       AIVCore::AIV0};
    waitB.SetAIVCore(AIVCore::AIV0);
    auto& sqrt = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SQRT, {ts[4]}, {ts[5]});
    Operation& setB = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SYNC_SRC, emptyInput, emptyOutput);
    setB.syncQueue_ = {PipeType::PIPE_V, PipeType::PIPE_MTE3, CoreType::AIV, CoreType::AIV,
                       IS_NUM4,          AIVCore::AIV0,       AIVCore::AIV0};
    setB.SetAIVCore(AIVCore::AIV0);
    add.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    exp.SetAtomicScopeId(VF_SCOPE_B);
    sqrt.SetAtomicScopeId(VF_SCOPE_B);
    add.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    exp.SetAIVCore(AIVCore::AIV0);
    sqrt.SetAIVCore(AIVCore::AIV0);
    // 原始顺序: add, waitA, cast, setA, exp, waitB, sqrt, setB
    std::vector<Operation*> opList = {&add, &waitA, &cast, &setA, &exp, &waitB, &sqrt, &setB};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), SUCCESS);

    // cluster A: waitA 移到 add 前，setA 移到 cast 后
    // cluster B: waitB 移到 exp 前，setB 移到 sqrt 后
    // 两个 cluster 相邻，但各自的 sync 仍然移到各自边界
    ExpectOpListEq(opList, {&waitA, &add, &cast, &setA, &waitB, &exp, &sqrt, &setB});
}

// 同一 cluster 内多条 sync 指令，移动后保持原始相对顺序
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopePreservesSyncOrderWithinCluster)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestPreserveSyncOrder");
    (void)root;
    auto ts = MakeTensors(IS_NUM6, {IS_NUM8, IS_NUM16});
    // cluster: add, exp, cast, neg, sqrt (atomicScopeId=7)
    // 内部有 2 条 wait-like 和 2 条 set-like，每条都被 cluster op 隔开（run length = 1）
    // 使用不同 eventId 避免配对检查失败
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& wait1 = CreateAtomicScopeSyncOp(*leaf, Opcode::OP_SYNC_DST);
    auto& exp = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_EXP, {ts[2]}, {ts[3]});
    std::vector<std::shared_ptr<LogicalTensor>> emptyInput;
    std::vector<std::shared_ptr<LogicalTensor>> emptyOutput;
    Operation& set1 = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SYNC_SRC, emptyInput, emptyOutput);
    set1.syncQueue_ = {PipeType::PIPE_V, PipeType::PIPE_MTE2, CoreType::AIV, CoreType::AIV,
                       IS_NUM2,          AIVCore::AIV0,       AIVCore::AIV0};
    set1.SetAIVCore(AIVCore::AIV0);
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[3]}, {ts[4]});
    Operation& wait2 = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SYNC_DST, emptyInput, emptyOutput);
    wait2.syncQueue_ = {PipeType::PIPE_MTE3, PipeType::PIPE_V, CoreType::AIV, CoreType::AIV, IS_NUM4,
                        AIVCore::AIV0,       AIVCore::AIV0};
    wait2.SetAIVCore(AIVCore::AIV0);
    auto& neg = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_NEG, {ts[4]}, {ts[5]});
    Operation& set2 = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SYNC_SRC, emptyInput, emptyOutput);
    set2.syncQueue_ = {PipeType::PIPE_V, PipeType::PIPE_MTE2, CoreType::AIV, CoreType::AIV,
                       IS_NUM5,          AIVCore::AIV0,       AIVCore::AIV0};
    set2.SetAIVCore(AIVCore::AIV0);
    auto& sqrt = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SQRT, {ts[5]}, {ts[0]});
    add.SetAtomicScopeId(VF_SCOPE_A);
    exp.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    neg.SetAtomicScopeId(VF_SCOPE_A);
    sqrt.SetAtomicScopeId(VF_SCOPE_A);
    add.SetAIVCore(AIVCore::AIV0);
    exp.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    neg.SetAIVCore(AIVCore::AIV0);
    sqrt.SetAIVCore(AIVCore::AIV0);
    // 原始顺序: add, wait1, exp, set1, cast, wait2, neg, set2, sqrt
    // 每条 sync 都被 cluster op 隔开，run length = 1
    // eventId 各不相同，不会触发配对检查
    std::vector<Operation*> opList = {&add, &wait1, &exp, &set1, &cast, &wait2, &neg, &set2, &sqrt};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), SUCCESS);

    // wait1, wait2 移到 cluster 前（保持原始出现顺序: wait1 在 wait2 前）
    // set1, set2 移到 cluster 后（保持原始出现顺序: set1 在 set2 前）
    ExpectOpListEq(opList, {&wait1, &wait2, &add, &exp, &cast, &neg, &sqrt, &set1, &set2});
}

// cluster 区间内交错另一核（AIV1）的 op（无 scope 辅助 op 与另一核 cluster op），跳过挪动判定不报错，
// 本核 sync 正常挪动，外来 op 保持原位
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeSkipsForeignCoreOps)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestSkipForeignCoreOps");
    (void)root;
    auto ts = MakeTensors(IS_NUM6, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    std::vector<std::shared_ptr<LogicalTensor>> emptyInput;
    std::vector<std::shared_ptr<LogicalTensor>> emptyOutput;
    Operation& cvSet = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CV_SYNC_SRC, emptyInput, emptyOutput);
    cvSet.syncQueue_ = {PipeType::PIPE_M, PipeType::PIPE_V, CoreType::AIC, CoreType::AIV,
                        IS_NUM1,          AIVCore::AIV0,    AIVCore::AIV1};
    cvSet.SetAIVCore(AIVCore::AIV0);
    // 模拟 OOO 交错发射的另一核 op: AIV1 无 scope 辅助 op + AIV1 另一 cluster 的 calc op
    auto& foreignMove = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_UB_COPY_ND2NZ, {ts[2]}, {ts[3]});
    auto& foreignCalc = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_EXP, {ts[3]}, {ts[4]});
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[4]}, {ts[5]});
    add.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    foreignCalc.SetAtomicScopeId(VF_SCOPE_B);
    add.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    foreignMove.SetAIVCore(AIVCore::AIV1);
    foreignCalc.SetAIVCore(AIVCore::AIV1);
    std::vector<Operation*> opList = {&add, &cvSet, &foreignMove, &foreignCalc, &cast};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), SUCCESS);

    // 默认模式：本核 cvSet 移到 cluster 后，另一核 op 保持原位
    ExpectOpListEq(opList, {&add, &foreignMove, &foreignCalc, &cast, &cvSet});
}

// 窗口内夹带同核 scope=-1 op（如用户 scope cluster 内未压实的搬运）：整 cluster 跳过调整而非报错
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeSkipsClusterWithUnscopedOpInside)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestUnscopedInside");
    (void)root;
    auto ts = MakeTensors(IS_NUM16, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& wait = CreateAtomicScopeSyncOp(*leaf, Opcode::OP_SYNC_DST);
    // 同核但无 scope 的搬运 op，夹在 cluster 窗口内
    auto& copy = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_UB_COPY_ND2NZ, {ts[2]}, {ts[3]});
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[3]}, {ts[4]});
    add.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    add.SetAIVCore(AIVCore::AIV0);
    copy.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    std::vector<Operation*> opList = {&add, &wait, &copy, &cast};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), SUCCESS);

    // cluster 被跳过：wait 保持原位
    ExpectOpListEq(opList, {&add, &wait, &copy, &cast});
}

// 用户设置的 atomic_scope（scopeId < VF_CLUSTER_ID_START）：前序处理直接跳过，不收集不检测，VF 簇正常调整
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeSkipsUserScopedClusters)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestSkipUserScope");
    (void)root;
    auto ts = MakeTensors(IS_NUM6, {IS_NUM8, IS_NUM16});
    // 用户 scope 簇：wait 保持原位不挪动
    auto& userAdd = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    auto& userWait = CreateAtomicScopeSyncOp(*leaf, Opcode::OP_SYNC_DST);
    auto& userCast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[2]}, {ts[3]});
    // VF 簇：set 正常移到 cluster 后
    auto& vfAdd = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_EXP, {ts[3]}, {ts[4]});
    auto& vfSet = CreateAtomicScopeSyncOp(*leaf, Opcode::OP_SYNC_SRC);
    auto& vfCast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SUB, {ts[4]}, {ts[5]});
    constexpr int userScopeId = 7 * 10000 + 3;
    userAdd.SetAtomicScopeId(userScopeId);
    userCast.SetAtomicScopeId(userScopeId);
    vfAdd.SetAtomicScopeId(VF_SCOPE_A);
    vfCast.SetAtomicScopeId(VF_SCOPE_A);
    userAdd.SetAIVCore(AIVCore::AIV0);
    userCast.SetAIVCore(AIVCore::AIV0);
    vfAdd.SetAIVCore(AIVCore::AIV0);
    vfCast.SetAIVCore(AIVCore::AIV0);
    std::vector<Operation*> opList = {&userAdd, &userWait, &userCast, &vfAdd, &vfSet, &vfCast};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), SUCCESS);

    // 用户 scope 簇：wait 原位；VF 簇：set 移到 cluster 后
    ExpectOpListEq(opList, {&userAdd, &userWait, &userCast, &vfAdd, &vfCast, &vfSet});
}

// cluster 区间内交错另一核（AIV1）的 sync op，不收集不挪动、保持原位，本核 sync 正常挪动
TEST_F(InsertSyncTest, AdjustSyncByAtomicScopeSkipsForeignCoreSyncs)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestSkipForeignCoreSyncs");
    (void)root;
    auto ts = MakeTensors(IS_NUM4, {IS_NUM8, IS_NUM16});
    auto& add = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    std::vector<std::shared_ptr<LogicalTensor>> emptyInput;
    std::vector<std::shared_ptr<LogicalTensor>> emptyOutput;
    Operation& wait = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SYNC_DST, emptyInput, emptyOutput);
    wait.syncQueue_ = {PipeType::PIPE_MTE2, PipeType::PIPE_V, CoreType::AIV, CoreType::AIV, IS_NUM1,
                       AIVCore::AIV0,       AIVCore::AIV0};
    wait.SetAIVCore(AIVCore::AIV0);
    // 模拟 OOO 交错发射的另一核（AIV1）sync
    Operation& foreignSyncSrc = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SYNC_SRC, emptyInput, emptyOutput);
    foreignSyncSrc.syncQueue_ = {PipeType::PIPE_V, PipeType::PIPE_MTE3, CoreType::AIV, CoreType::AIV,
                                 IS_NUM2,          AIVCore::AIV1,       AIVCore::AIV1};
    foreignSyncSrc.SetAIVCore(AIVCore::AIV1);
    Operation& foreignSyncDst = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_SYNC_DST, emptyInput, emptyOutput);
    foreignSyncDst.syncQueue_ = {PipeType::PIPE_MTE3, PipeType::PIPE_V, CoreType::AIV, CoreType::AIV, IS_NUM3,
                                 AIVCore::AIV1,       AIVCore::AIV1};
    foreignSyncDst.SetAIVCore(AIVCore::AIV1);
    auto& cast = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[2]}, {ts[3]});
    add.SetAtomicScopeId(VF_SCOPE_A);
    cast.SetAtomicScopeId(VF_SCOPE_A);
    add.SetAIVCore(AIVCore::AIV0);
    cast.SetAIVCore(AIVCore::AIV0);
    std::vector<Operation*> opList = {&add, &wait, &foreignSyncSrc, &foreignSyncDst, &cast};

    InsertSync syncPass;
    EXPECT_EQ(syncPass.AdjustSyncByAtomicScope(opList, {}), SUCCESS);

    // 默认模式：本核 wait 移到 cluster 前，另一核 sync 保持原位
    ExpectOpListEq(opList, {&wait, &add, &foreignSyncSrc, &foreignSyncDst, &cast});
}

// =========================================================================
// 端到端测试：通过 RunOnFunction 走完整 normal 路径
// PipeSync::InsertSync → PhaseKernelProcess → AdjustSyncByAtomicScope
// =========================================================================

// Helper: 创建带 UB memory range 的 tensor
static std::shared_ptr<LogicalTensor> MakeUbTensor(int start, int end)
{
    std::vector<int64_t> shape = {IS_NUM8, IS_NUM16};
    auto t = npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
    t->SetMemoryTypeBoth(MemoryType::MEM_UB);
    t->memoryrange.start = start;
    t->memoryrange.end = end;
    return t;
}

// Helper: 创建 GM tensor
static std::shared_ptr<LogicalTensor> MakeGmTensor()
{
    std::vector<int64_t> shape = {IS_NUM8, IS_NUM16};
    return npu::tile_fwk::IRBuilder().CreateTensorVar(DT_FP32, shape, CreateTestConstIntVector(shape));
}

// Helper: 创建 copy_in op (GM → UB)，带 CopyOpAttribute
static Operation& MakeCopyInOp(Function& func, std::shared_ptr<LogicalTensor> gm, std::shared_ptr<LogicalTensor> ub)
{
    std::vector<int64_t> shape = {IS_NUM8, IS_NUM16};
    auto& op = IRBuilder().CreateTensorOpStmt(func, Opcode::OP_COPY_IN, {gm}, {ub});
    op.SetOpAttribute(std::make_shared<CopyOpAttribute>(std::vector<OpImmediate>{}, MemoryType::MEM_UB,
                                                        std::vector<OpImmediate>{OpImmediate::Specified(shape)},
                                                        std::vector<OpImmediate>{OpImmediate::Specified(shape)}));
    op.SetAIVCore(AIVCore::AIV0);
    return op;
}

// Helper: 创建 copy_out op (UB → GM)，带 CopyOpAttribute
static Operation& MakeCopyOutOp(Function& func, std::shared_ptr<LogicalTensor> ub, std::shared_ptr<LogicalTensor> gm)
{
    std::vector<int64_t> shape = {IS_NUM8, IS_NUM16};
    auto& op = IRBuilder().CreateTensorOpStmt(func, Opcode::OP_COPY_OUT, {ub}, {gm});
    op.SetOpAttribute(std::make_shared<CopyOpAttribute>(MemoryType::MEM_UB, std::vector<OpImmediate>{},
                                                        std::vector<OpImmediate>{OpImmediate::Specified(shape)},
                                                        std::vector<OpImmediate>{OpImmediate::Specified(shape)}));
    op.SetAIVCore(AIVCore::AIV0);
    return op;
}

// Helper: 创建 root + leaf function pair
static std::pair<std::shared_ptr<Function>, std::shared_ptr<Function>> CreateRootAndLeaf(const std::string& name)
{
    auto root = std::make_shared<Function>(Program::GetInstance(), name, name, nullptr);
    root->rootFunc_ = root.get();
    auto leaf = std::make_shared<Function>(Program::GetInstance(), name + "Leaf", name + "Leaf", root.get());
    root->rootFunc_->programs_.emplace(leaf->GetFuncMagic(), leaf.get());
    return {root, leaf};
}

// Helper: 验证 firstOp 和 lastOp 之间没有 sync op
static void VerifyNoSyncBetween(const std::vector<Operation*>& ops, Operation* firstOp, Operation* lastOp)
{
    bool foundFirst = false;
    bool foundLast = false;
    bool hasSync = false;
    for (auto* op : ops) {
        if (op == firstOp) {
            foundFirst = true;
            continue;
        }
        if (op == lastOp) {
            foundLast = true;
            continue;
        }
        if (foundFirst && !foundLast &&
            (op->GetOpcode() == Opcode::OP_SYNC_SRC || op->GetOpcode() == Opcode::OP_SYNC_DST)) {
            hasSync = true;
        }
    }
    EXPECT_TRUE(foundFirst);
    EXPECT_TRUE(foundLast);
    EXPECT_FALSE(hasSync) << "sync op found inside cluster";
}

// Helper: 验证 targetOp 之前有指定 sync opcode
static void VerifyHasSyncBefore(const std::vector<Operation*>& ops, Operation* targetOp, Opcode syncOpcode)
{
    bool found = false;
    for (auto* op : ops) {
        if (op == targetOp) {
            break;
        }
        if (op->GetOpcode() == syncOpcode) {
            found = true;
        }
    }
    EXPECT_TRUE(found) << "no sync before target op";
}

// Helper: 验证 targetOp 之后有指定 sync opcode
static void VerifyHasSyncAfter(const std::vector<Operation*>& ops, Operation* targetOp, Opcode syncOpcode)
{
    bool afterTarget = false;
    bool found = false;
    for (auto* op : ops) {
        if (op == targetOp) {
            afterTarget = true;
            continue;
        }
        if (afterTarget && op->GetOpcode() == syncOpcode) {
            found = true;
        }
    }
    EXPECT_TRUE(found) << "no sync after target op";
}

// Helper: 验证两个 op 之间有指定 sync opcode
static void VerifyHasSyncBetween(const std::vector<Operation*>& ops, Operation* firstOp, Operation* lastOp,
                                 Opcode syncOpcode)
{
    bool afterFirst = false;
    bool found = false;
    for (auto* op : ops) {
        if (op == firstOp) {
            afterFirst = true;
            continue;
        }
        if (op == lastOp) {
            break;
        }
        if (afterFirst && op->GetOpcode() == syncOpcode) {
            found = true;
        }
    }
    EXPECT_TRUE(found) << "no sync between ops";
}

// 端到端：cluster 内部有跨 pipe 依赖产生的 sync，验证 sync 被移到 cluster 边界
// 构图: copy_in(a) copy_in(b) → exp(a→c) add(c,b→d) sub(d→e) → copy_out(d) copy_out(e)
// exp/add/sub 设为同一 cluster，copy_in(b)→add 的 sync 会落在 cluster 内部
TEST_F(InsertSyncTest, EndToEndSyncMovedToClusterBoundary)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [rootFuncPtr, leafFuncPtr] = CreateRootAndLeaf("E2EBoundary");

    auto ubA = MakeUbTensor(0, IS_NUM99);
    auto ubB = MakeUbTensor(IS_NUM100, IS_NUM199);
    auto ubC = MakeUbTensor(IS_NUM200, IS_NUM299);
    auto ubD = MakeUbTensor(IS_NUM300, IS_NUM300 + IS_NUM99);
    auto ubE = MakeUbTensor(IS_NUM500, IS_NUM500 + IS_NUM99);
    MakeCopyInOp(*leafFuncPtr, MakeGmTensor(), ubA);
    MakeCopyInOp(*leafFuncPtr, MakeGmTensor(), ubB);
    auto& exp = IRBuilder().CreateTensorOpStmt(*leafFuncPtr, Opcode::OP_EXP, {ubA}, {ubC});
    exp.SetAIVCore(AIVCore::AIV0);
    auto& add = IRBuilder().CreateTensorOpStmt(*leafFuncPtr, Opcode::OP_ADD, {ubC, ubB}, {ubD});
    add.SetAIVCore(AIVCore::AIV0);
    auto& sub = IRBuilder().CreateTensorOpStmt(*leafFuncPtr, Opcode::OP_SUB, {ubD}, {ubE});
    sub.SetAIVCore(AIVCore::AIV0);
    MakeCopyOutOp(*leafFuncPtr, ubD, MakeGmTensor());
    MakeCopyOutOp(*leafFuncPtr, ubE, MakeGmTensor());

    constexpr int clusterId = 200000000;
    exp.SetAtomicScopeId(clusterId);
    add.SetAtomicScopeId(clusterId);
    sub.SetAtomicScopeId(clusterId);

    InsertSync syncPass;
    ASSERT_EQ(syncPass.RunOnFunction(*rootFuncPtr), SUCCESS);
    auto ops = leafFuncPtr->Operations(false).DuplicatedOpList();

    VerifyNoSyncBetween(ops, &exp, &sub);
    VerifyHasSyncBefore(ops, &exp, Opcode::OP_SYNC_DST);
    VerifyHasSyncAfter(ops, &sub, Opcode::OP_SYNC_SRC);
}

// 端到端：两个相邻 cluster，各自内部有跨 pipe sync，验证互不干扰
// 构图: copy_in(a) copy_in(b) copy_in(c2) → exp add | sqrt cast → copy_out(d) copy_out(f)
// cluster A: exp,add  cluster B: sqrt,cast  相邻
TEST_F(InsertSyncTest, EndToEndAdjacentClustersSyncMovedIndependently)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [rootFuncPtr, leafFuncPtr] = CreateRootAndLeaf("E2EAdj");

    auto ubA = MakeUbTensor(0, IS_NUM99);
    auto ubB = MakeUbTensor(IS_NUM100, IS_NUM199);
    auto ubC = MakeUbTensor(IS_NUM200, IS_NUM299);
    auto ubD = MakeUbTensor(IS_NUM300, IS_NUM300 + IS_NUM99);
    auto ubE = MakeUbTensor(IS_NUM500, IS_NUM500 + IS_NUM99);
    auto ubF = MakeUbTensor(IS_NUM600, IS_NUM699);
    auto ubC2 = MakeUbTensor(IS_NUM700, IS_NUM800);
    MakeCopyInOp(*leafFuncPtr, MakeGmTensor(), ubA);
    MakeCopyInOp(*leafFuncPtr, MakeGmTensor(), ubB);
    MakeCopyInOp(*leafFuncPtr, MakeGmTensor(), ubC2);
    auto& exp = IRBuilder().CreateTensorOpStmt(*leafFuncPtr, Opcode::OP_EXP, {ubA}, {ubC});
    exp.SetAIVCore(AIVCore::AIV0);
    auto& add = IRBuilder().CreateTensorOpStmt(*leafFuncPtr, Opcode::OP_ADD, {ubC, ubB}, {ubD});
    add.SetAIVCore(AIVCore::AIV0);
    auto& sqrt = IRBuilder().CreateTensorOpStmt(*leafFuncPtr, Opcode::OP_SQRT, {ubD}, {ubE});
    sqrt.SetAIVCore(AIVCore::AIV0);
    auto& cast = IRBuilder().CreateTensorOpStmt(*leafFuncPtr, Opcode::OP_CAST, {ubE, ubC2}, {ubF});
    cast.SetAIVCore(AIVCore::AIV0);
    MakeCopyOutOp(*leafFuncPtr, ubD, MakeGmTensor());
    MakeCopyOutOp(*leafFuncPtr, ubF, MakeGmTensor());

    constexpr int clusterA = 200000000;
    constexpr int clusterB = 200000001;
    exp.SetAtomicScopeId(clusterA);
    add.SetAtomicScopeId(clusterA);
    sqrt.SetAtomicScopeId(clusterB);
    cast.SetAtomicScopeId(clusterB);

    InsertSync syncPass;
    ASSERT_EQ(syncPass.RunOnFunction(*rootFuncPtr), SUCCESS);
    auto ops = leafFuncPtr->Operations(false).DuplicatedOpList();

    VerifyNoSyncBetween(ops, &exp, &add);
    VerifyNoSyncBetween(ops, &sqrt, &cast);
    VerifyHasSyncBefore(ops, &exp, Opcode::OP_SYNC_DST);
    VerifyHasSyncBetween(ops, &add, &sqrt, Opcode::OP_SYNC_DST);
    VerifyHasSyncAfter(ops, &cast, Opcode::OP_SYNC_SRC);
}

// 3510: AIV 同流水(PIPE_MTE3, assemble/COPY_OUT 场景)数据依赖必须生成 OP_BAR_M, 不能丢弃
TEST_F(InsertSyncTest, TestGenSyncOpAivSameMte3PipeOn3510GeneratesBarM)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestGenSyncAivMte3");
    auto ts = MakeTensors(IS_NUM2, {IS_NUM8, IS_NUM16});
    Operation& op = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0]}, {ts[1]});
    PipeSync ps;
    PipeSync::PipeCoreRealEx set(PipeType::PIPE_MTE3, CoreType::AIV, AIVCore::AIV0);
    PipeSync::PipeCoreRealEx wait(PipeType::PIPE_MTE3, CoreType::AIV, AIVCore::AIV0);
    EXPECT_TRUE(ps.GenSyncOp(set, wait, IS_NUM1, false, op));
    EXPECT_EQ(op.GetOpcode(), Opcode::OP_BAR_M);
    EXPECT_EQ(op.syncQueue_.pipeId_, PipeType::PIPE_MTE3);
    EXPECT_EQ(op.syncQueue_.trigPipeId_, PipeType::PIPE_MTE3);
    EXPECT_EQ(op.syncQueue_.coreType_, CoreType::AIV);
    EXPECT_EQ(op.syncQueue_.trigCoreType_, CoreType::AIV);
    EXPECT_EQ(op.syncQueue_.eventId_, IS_NUM1);
}

// lite(3113): AIV 同流水(PIPE_MTE3)数据依赖同样必须生成 OP_BAR_M, 不能丢弃
TEST_F(InsertSyncTest, TestGenSyncOpAivSameMte3PipeOnLiteGeneratesBarM)
{
    NpuArchScope scopedArch(NPUArch::DAV_3113);
    auto [root, leaf] = SetupDebugFunc("TestGenSyncAivMte3Lite");
    auto ts = MakeTensors(IS_NUM2, {IS_NUM8, IS_NUM16});
    Operation& op = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0]}, {ts[1]});
    PipeSync ps;
    PipeSync::PipeCoreRealEx set(PipeType::PIPE_MTE3, CoreType::AIV, AIVCore::AIV0);
    PipeSync::PipeCoreRealEx wait(PipeType::PIPE_MTE3, CoreType::AIV, AIVCore::AIV0);
    EXPECT_TRUE(ps.GenSyncOp(set, wait, IS_NUM1, false, op));
    EXPECT_EQ(op.GetOpcode(), Opcode::OP_BAR_M);
}

// 3510: AIV V->V 同步维持原行为, 不生成同步 op
TEST_F(InsertSyncTest, TestGenSyncOpAivVVPipeOn3510KeepsSkip)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestGenSyncAivV3510");
    auto ts = MakeTensors(IS_NUM2, {IS_NUM8, IS_NUM16});
    Operation& op = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0]}, {ts[1]});
    PipeSync ps;
    PipeSync::PipeCoreRealEx set(PipeType::PIPE_V, CoreType::AIV, AIVCore::AIV0);
    PipeSync::PipeCoreRealEx wait(PipeType::PIPE_V, CoreType::AIV, AIVCore::AIV0);
    EXPECT_FALSE(ps.GenSyncOp(set, wait, IS_NUM1, false, op));
}

// 非 3510 非 lite(2201): AIV V->V 仍生成 OP_BAR_V(原有行为)
TEST_F(InsertSyncTest, TestGenSyncOpAivVVPipeOn2201GeneratesBarV)
{
    NpuArchScope scopedArch(NPUArch::DAV_2201);
    auto [root, leaf] = SetupDebugFunc("TestGenSyncAivV2201");
    auto ts = MakeTensors(IS_NUM2, {IS_NUM8, IS_NUM16});
    Operation& op = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0]}, {ts[1]});
    PipeSync ps;
    PipeSync::PipeCoreRealEx set(PipeType::PIPE_V, CoreType::AIV, AIVCore::AIV0);
    PipeSync::PipeCoreRealEx wait(PipeType::PIPE_V, CoreType::AIV, AIVCore::AIV0);
    EXPECT_TRUE(ps.GenSyncOp(set, wait, IS_NUM1, false, op));
    EXPECT_EQ(op.GetOpcode(), Opcode::OP_BAR_V);
}

// isSet=true: 源头侧不生成同步 op(原有行为)
TEST_F(InsertSyncTest, TestGenSyncOpAivSamePipeSetSideNoop)
{
    NpuArchScope scopedArch(NPUArch::DAV_3510);
    auto [root, leaf] = SetupDebugFunc("TestGenSyncAivSetSide");
    auto ts = MakeTensors(IS_NUM2, {IS_NUM8, IS_NUM16});
    Operation& op = IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0]}, {ts[1]});
    PipeSync ps;
    PipeSync::PipeCoreRealEx set(PipeType::PIPE_MTE3, CoreType::AIV, AIVCore::AIV0);
    PipeSync::PipeCoreRealEx wait(PipeType::PIPE_MTE3, CoreType::AIV, AIVCore::AIV0);
    EXPECT_FALSE(ps.GenSyncOp(set, wait, IS_NUM1, true, op));
}

// cvHardSync debug mode：无CV边界（纯vec函数）正常完成，不插入跨核硬同步
TEST_F(InsertSyncTest, TestCvHardSyncNoBoundary)
{
    auto currFunctionPtr = std::make_shared<Function>(Program::GetInstance(), "TestCvHardSyncVec", "TestCvHardSyncVec",
                                                      nullptr);

    auto incast1 = MakeGmTensor();
    auto incast2 = MakeGmTensor();
    auto ubTensor1 = MakeUbTensor(0, IS_NUM100);
    auto ubTensor2 = MakeUbTensor(IS_NUM200, IS_NUM300);
    auto ubTensor3 = MakeUbTensor(IS_NUM300, IS_NUM499);
    auto outCast = MakeGmTensor();

    MakeCopyInOp(*currFunctionPtr, incast1, ubTensor1);
    MakeCopyInOp(*currFunctionPtr, incast2, ubTensor2);
    auto& addOp = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_ADD, {ubTensor1, ubTensor2}, {ubTensor3});
    (void)addOp;
    addOp.SetAIVCore(AIVCore::AIV0);
    MakeCopyOutOp(*currFunctionPtr, ubTensor3, outCast);
    currFunctionPtr->inCasts_.push_back(incast1);
    currFunctionPtr->inCasts_.push_back(incast2);
    currFunctionPtr->outCasts_.push_back(outCast);

    InsertSync syncPass;
    syncPass.SetCvHardSync(true);
    EXPECT_EQ(syncPass.InsertSyncMainLoop(currFunctionPtr.get()), SUCCESS);
    for (auto& op : currFunctionPtr->Operations()) {
        EXPECT_NE(op.GetOpcode(), Opcode::OP_FFTS_CROSS_CORE_SYNC) << "No CV boundary, hard sync should not appear";
    }
}

// cvHardSync debug mode：vec→cube→vec混合函数在每个核切换处插入1C2V硬同步
TEST_F(InsertSyncTest, TestCvHardSyncWithBoundary)
{
    auto currFunctionPtr = std::make_shared<Function>(Program::GetInstance(), "TestCvHardSyncMix", "TestCvHardSyncMix",
                                                      nullptr);

    auto incast = MakeGmTensor();
    auto ubTensor1 = MakeUbTensor(0, IS_NUM100);
    auto ubTensor2 = MakeUbTensor(IS_NUM200, IS_NUM300);
    auto ubTensor3 = MakeUbTensor(IS_NUM300, IS_NUM499);
    auto outCast = MakeGmTensor();

    MakeCopyInOp(*currFunctionPtr, incast, ubTensor1);
    auto& cubeOp = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_A_MUL_B, {ubTensor1, ubTensor1},
                                                  {ubTensor2});
    (void)cubeOp;
    auto& addOp = IRBuilder().CreateTensorOpStmt(*currFunctionPtr, Opcode::OP_ADD, {ubTensor2}, {ubTensor3});
    (void)addOp;
    addOp.SetAIVCore(AIVCore::AIV0);
    MakeCopyOutOp(*currFunctionPtr, ubTensor3, outCast);
    currFunctionPtr->inCasts_.push_back(incast);
    currFunctionPtr->outCasts_.push_back(outCast);

    InsertSync syncPass;
    syncPass.SetCvHardSync(true);
    EXPECT_EQ(syncPass.InsertSyncMainLoop(currFunctionPtr.get()), SUCCESS);
    bool hasHardSync = false;
    for (auto& op : currFunctionPtr->Operations()) {
        if (op.GetOpcode() == Opcode::OP_FFTS_CROSS_CORE_SYNC) {
            hasHardSync = true;
        }
    }
    EXPECT_TRUE(hasHardSync) << "CV boundary exists, 1C2V hard sync should be inserted";
}

// ENABLE_PIPE_ALL 全同步调试开关：InsertSyncMainLoop 直接走 InsertPipeAll，
// 在相邻非 RESHAPE/VIEW/VIEW_TYPE/ASSEMBLE op 之间插入 OP_BAR_ALL。
TEST_F(InsertSyncTest, TestInsertPipeAll)
{
    config::SetPassGlobalConfig(KEY_ENABLE_PIPE_ALL, true);
    auto [root, leaf] = SetupDebugFunc("TestPipeAll");
    auto ts = MakeTensors(IS_NUM7, {IS_NUM8, IS_NUM16});
    (void)IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0], ts[1]}, {ts[2]});
    (void)IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_RESHAPE, {ts[2]}, {ts[3]});
    (void)IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_VIEW, {ts[3]}, {ts[4]});
    (void)IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_CAST, {ts[4]}, {ts[5]});
    (void)IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_EXP, {ts[5]}, {ts[6]});
    InsertSync syncPass;
    syncPass.RunOnFunction(*root);
    // 原始 op 列表保持不变
    EXPECT_EQ(leaf->oriOpList.size(), static_cast<size_t>(IS_NUM5));
    // ADD BAR_ALL RESHAPE VIEW CAST BAR_ALL EXP
    auto ops = leaf->Operations(false).DuplicatedOpList();
    EXPECT_EQ(ops.size(), static_cast<size_t>(IS_NUM7));
    EXPECT_EQ(ops[0]->GetOpcode(), Opcode::OP_ADD);
    EXPECT_EQ(ops[IS_NUM1]->GetOpcode(), Opcode::OP_BAR_ALL);
    EXPECT_EQ(ops[IS_NUM2]->GetOpcode(), Opcode::OP_RESHAPE);
    EXPECT_EQ(ops[IS_NUM3]->GetOpcode(), Opcode::OP_VIEW);
    EXPECT_EQ(ops[IS_NUM4]->GetOpcode(), Opcode::OP_CAST);
    EXPECT_EQ(ops[IS_NUM5]->GetOpcode(), Opcode::OP_BAR_ALL);
    EXPECT_EQ(ops[IS_NUM6]->GetOpcode(), Opcode::OP_EXP);
}

// ENABLE_PIPE_ALL 边界：单 op 无相邻 op，不插入任何 OP_BAR_ALL。
TEST_F(InsertSyncTest, TestInsertPipeAllSingleOp)
{
    config::SetPassGlobalConfig(KEY_ENABLE_PIPE_ALL, true);
    auto [root, leaf] = SetupDebugFunc("TestPipeAllSingle");
    auto ts = MakeTensors(IS_NUM2, {IS_NUM8, IS_NUM16});
    (void)IRBuilder().CreateTensorOpStmt(*leaf, Opcode::OP_ADD, {ts[0]}, {ts[1]});
    InsertSync syncPass;
    syncPass.RunOnFunction(*root);
    EXPECT_EQ(leaf->oriOpList.size(), static_cast<size_t>(IS_NUM1));
    auto ops = leaf->Operations(false).DuplicatedOpList();
    EXPECT_EQ(ops.size(), static_cast<size_t>(IS_NUM1));
    EXPECT_EQ(ops[0]->GetOpcode(), Opcode::OP_ADD);
}

} // namespace tile_fwk
} // namespace npu

#undef private
