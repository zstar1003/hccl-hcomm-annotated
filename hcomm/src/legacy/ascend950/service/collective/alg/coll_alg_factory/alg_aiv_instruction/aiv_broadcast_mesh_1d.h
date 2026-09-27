/**
 * Copyright (c) 2025 Huawei Technologies Co., Ltd.
 * This program is free software, you can redistribute it and/or modify it under the terms and conditions of
 * CANN Open Software License Agreement Version 2.0 (the "License").
 * Please refer to the License for details. You may not use this file except in compliance with the License.
 * THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND, EITHER EXPRESS OR IMPLIED,
 * INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY, OR FITNESS FOR A PARTICULAR PURPOSE.
 * See LICENSE in the root of the software repository for the full text of the License.
 */

#include "aiv_communication_base_v2.h"

using namespace AscendC;

// todo 简化参数

class AivBroadcastMesh1D : public AivCommBase {
public:
    __aicore__ inline AivBroadcastMesh1D() {}

    template <typename T>
    __aicore__ inline void Process(uint64_t curCount, uint64_t curTag);

    template <typename T>
    __aicore__ inline void ProcessBigData(uint64_t curCount, uint64_t curTag);
};

template <typename T>
__aicore__ inline void AivBroadcastMesh1D::Process(uint64_t curCount, uint64_t curTag)
{
    uint64_t dataTypeSize = sizeof(T);
    if (block_idx >= rankSize_) {
        return;
    }
    uint32_t peerRank = block_idx;
    uint64_t offsetPerCore = curCount / rankSize_ * dataTypeSize;
    uint64_t dataOffset = offsetPerCore * block_idx;
    uint64_t countPerCore
        = block_idx == rankSize_ - 1 ? curCount - (rankSize_ - 1) * (curCount / rankSize_) : curCount / rankSize_;
    uint64_t flag_offset = block_idx;
    __gm__ T* inputGM = (__gm__ T*)(input_ + dataOffset);
    __gm__ T* cclGM = (__gm__ T*)(GM_IN[peerRank] + dataOffset);
    // scatter
    if (rank_ == root_) {
        CpGM2GM(cclGM, inputGM, countPerCore);
        PipeBarrier<PIPE_ALL>();
        Record(peerRank, flag_offset, curTag);
    }

    // allgather
    WaitFlag(peerRank, flag_offset, curTag);
    CpGM2GM(inputGM, cclGM, countPerCore);
    PipeBarrier<PIPE_ALL>();
}

template <typename T>
__aicore__ inline void AivBroadcastMesh1D::ProcessBigData(uint64_t curCount, uint64_t curTag)
{
    // root节点先用全量核去写本卡cclBuffer，这里的每个核要对应多个flag，让其他卡可以用全量核来读
    // 然后其他卡用全量核去读数据
    // 最后做allgather
    uint64_t curStageCoreNum = numBlocks_ / rankSize_ * rankSize_;
    if (block_idx >= curStageCoreNum) {
        return;
    }

    uint64_t coreNumPerRank = curStageCoreNum / rankSize_;
    uint64_t targetRank = block_idx / coreNumPerRank;
    uint64_t coreIndex = (block_idx - (targetRank * coreNumPerRank)) % coreNumPerRank;
    uint64_t flag_offset = 0;

    // 先把数据按照rankSize 切分
    uint64_t dataPerRank = curCount / rankSize_;
    uint64_t rankRemainder = curCount % rankSize_;
    uint64_t rankInnerDispls = 0;
    uint64_t targetRankCurCount = 0;
    if (targetRank < rankRemainder) { // 这部分核需要多处理一个数据
        rankInnerDispls = targetRank * dataPerRank + targetRank;
        targetRankCurCount = dataPerRank + 1;
    } else {
        rankInnerDispls = targetRank * dataPerRank + rankRemainder;
        targetRankCurCount = dataPerRank;
    }

    // 给每个核划分数据
    uint64_t dataPerCore = targetRankCurCount / coreNumPerRank;
    uint64_t remainder = targetRankCurCount % coreNumPerRank;
    uint64_t innerDispls = 0;
    uint64_t sendCurCount = 0;
    if (coreIndex < remainder) { // 这部分核需要多处理一个数据
        innerDispls = coreIndex * dataPerCore + coreIndex;
        sendCurCount = dataPerCore + 1;
    } else {
        innerDispls = coreIndex * dataPerCore + remainder;
        sendCurCount = dataPerCore;
    }

    // root 开始本卡搬运数据:这里是全量卡都去搬比较好，还是就用rankSize的卡去搬
    uint64_t sendInputOffset = input_ + (rankInnerDispls + innerDispls) * sizeof(T);
    uint64_t sendCclInOffset = reinterpret_cast<uint64_t>(GM_IN[rank_]) + (rankInnerDispls + innerDispls) * sizeof(T);
    if ((rank_ == root_) && (sendCurCount > 0)) {
        CpGM2GM((__gm__ T*)sendCclInOffset, (__gm__ T*)sendInputOffset, sendCurCount);
        PipeBarrier<PIPE_ALL>();
        // targetRankCurCount这么多的数据量，有coreNumPerRank去写，但是有coreNumPerRank *
        // rankSize的核去读，所以一个核要写rankSize个flag
        for (uint64_t i = 0; i < rankSize_; i++) {
            Record(root_, block_idx * rankSize_ + i, curTag);
        }
    }

    // 现在除了root节点，其他卡要用全量核去拿root卡上的数据
    uint64_t rankInnerDisplsStage1 = 0;
    uint64_t targetRankCurCountStage1 = 0;
    if (rank_ < rankRemainder) { // 这部分核需要多处理一个数据
        rankInnerDisplsStage1 = rank_ * dataPerRank + rank_;
        targetRankCurCountStage1 = dataPerRank + 1;
    } else {
        rankInnerDisplsStage1 = rank_ * dataPerRank + rankRemainder;
        targetRankCurCountStage1 = dataPerRank;
    }
    // 给每rankSize个核划分数据
    uint64_t rankSizeCoreDataIndex = block_idx / rankSize_;
    uint64_t dataPerRankSizeCore = targetRankCurCountStage1 / coreNumPerRank;
    uint64_t rankSizeCoreRemainder = targetRankCurCountStage1 % coreNumPerRank;
    uint64_t rankSizeCoreInnerDispls = 0;
    uint64_t rankSizeCoreSendCurCount = 0;
    if (rankSizeCoreDataIndex < rankSizeCoreRemainder) { // 这部分核需要多处理一个数据
        rankSizeCoreInnerDispls = rankSizeCoreDataIndex * dataPerRankSizeCore + rankSizeCoreDataIndex;
        rankSizeCoreSendCurCount = dataPerRankSizeCore + 1;
    } else {
        rankSizeCoreInnerDispls = rankSizeCoreDataIndex * dataPerRankSizeCore + rankSizeCoreRemainder;
        rankSizeCoreSendCurCount = dataPerRankSizeCore;
    }

    // 给每个核划分数据
    uint64_t dataPerCoreStage1 = rankSizeCoreSendCurCount / rankSize_;
    uint64_t remainderStage1 = rankSizeCoreSendCurCount % rankSize_;
    uint64_t coreIndexStage1 = (block_idx - (rankSizeCoreDataIndex * rankSize_)) % rankSize_;
    uint64_t innerDisplsStage1 = 0;
    uint64_t sendCurCountStage1 = 0;
    if (coreIndexStage1 < remainderStage1) { // 这部分核需要多处理一个数据
        innerDisplsStage1 = coreIndexStage1 * dataPerCoreStage1 + coreIndexStage1;
        sendCurCountStage1 = dataPerCoreStage1 + 1;
    } else {
        innerDisplsStage1 = coreIndexStage1 * dataPerCoreStage1 + remainderStage1;
        sendCurCountStage1 = dataPerCoreStage1;
    }

    // 每个核开始去读数据
    uint64_t recvCclInOffset = reinterpret_cast<uint64_t>(GM_IN[root_])
                               + (rankInnerDisplsStage1 + rankSizeCoreInnerDispls + innerDisplsStage1) * sizeof(T);
    uint64_t recvCclOutOffset = reinterpret_cast<uint64_t>(GM_IN[rank_])
                                + (rankInnerDisplsStage1 + rankSizeCoreInnerDispls + innerDisplsStage1) * sizeof(T);
    if ((rank_ != root_) && (rankSizeCoreSendCurCount > 0)) {
        flag_offset = rank_ * coreNumPerRank * rankSize_ + rankSizeCoreDataIndex * rankSize_ + coreIndexStage1;
        WaitFlag(root_, flag_offset, curTag);
        CpGM2GM((__gm__ T*)recvCclOutOffset, (__gm__ T*)recvCclInOffset, sendCurCountStage1);
        PipeBarrier<PIPE_ALL>();
        Record(rank_, flag_offset, curTag);
    }

    // 最后所有的卡去做allgather,每个卡要读对面rankSize个flag
    uint64_t gatherSrcOffset
        = reinterpret_cast<uint64_t>(GM_IN[targetRank]) + (rankInnerDispls + innerDispls) * sizeof(T);
    uint64_t ouputOffset = input_ + (rankInnerDispls + innerDispls) * sizeof(T);
    if ((rank_ != root_) && (sendCurCount > 0)) {
        // 每块数据要去等rankSize个flag
        for (uint64_t i = 0; i < rankSize_; i++) {
            flag_offset = targetRank * coreNumPerRank * rankSize_ + coreIndex * rankSize_ + i;
            WaitFlag(targetRank, flag_offset, curTag);
        }
        CpGM2GM((__gm__ T*)ouputOffset, (__gm__ T*)gatherSrcOffset, sendCurCount);
        PipeBarrier<PIPE_ALL>();
    }
}

template <typename T>
__aicore__ inline void AivBroadcastV2Mesh1D(EXTERN_KERNEL_ARGS_DEF_V2)
{
    AivBroadcastMesh1D op;
    op.Init(KERNEL_CLASS_INIT, true);
    SyncAll<true>();
    if (block_idx == 0 && tag >> AIV_TAG_MOVE_RIGHT_BITS == 1 && (tag & LOW_16_BITS) == 1) {
        op.BarrierForFirstOP();
    }
    SyncAll<true>();
    if (len * sizeof(T) >= DATA_LIMIT) {
        op.ProcessBigData<T>(len, tag);
    } else {
        op.Process<T>(len, tag);
    }
    op.BarrierAll();
}
