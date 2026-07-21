/**
 * This program is free software, you can redistribute it and/or modify it.
 * Copyright (c) 2025 Huawei Technologies Co., Ltd.
 * This file is a part of the CANN Open Software.
 * Licensed under CANN Open Software License Agreement Version 2.0 (the "License").
 * Please refer to the License for details. You may not use this file except in compliance with the License.
 * THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND, EITHER EXPRESS OR IMPLIED, INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY, OR FITNESS FOR A PARTICULAR PURPOSE.
 * See LICENSE in the root of the software repository for the full text of the License.
 */

/*!
 * \file fused_sparse_attention_overlap_service_vector_mla.h
 * \brief
 */
#ifndef FUSED_SPARSE_ATTENTION_OVERLAP_SERVICE_VECTOR_MLA_H
#define FUSED_SPARSE_ATTENTION_OVERLAP_SERVICE_VECTOR_MLA_H

#include "kernel_operator.h"
#include "kernel_operator_list_tensor_intf.h"
#include "kernel_tiling/kernel_tiling.h"
#include "lib/matmul_intf.h"
#include "lib/matrix/matmul/tiling.h"
#include "fused_sparse_attention_overlap_common.h"

using AscendC::CrossCoreSetFlag;
using AscendC::CrossCoreWaitFlag;

template <typename FusedSparseAttentionOverlapTraits> class FusedSparseAttentionOverlapVectorService {
public:
    // 中间计算数据类型为float，高精度模式
    using T = float;
    using KV_T = typename FusedSparseAttentionOverlapTraits::kvType;
    using OUT_T = typename FusedSparseAttentionOverlapTraits::outputType;
    using UPDATE_T = T;
    using MM1_OUT_T = float;
    using MM2_OUT_T = float;

    __aicore__ inline FusedSparseAttentionOverlapVectorService(){};
    __aicore__ inline void ProcessVec1L(const RunInfo &info);
    __aicore__ inline void ProcessVec2L(const RunInfo &info);
    __aicore__ inline void InitBuffers(TPipe *pipe);
    __aicore__ inline void InitParams(const struct ConstInfo &constInfo,
                                      const FusedSparseAttentionOverlapTilingDataMla *__restrict tilingData);
    __aicore__ inline void InitMm2ResInt32GmGlobalTensor(GlobalTensor<int32_t> mm2ResInt32Gm);
    __aicore__ inline void InitVec0GlobalTensor(const GlobalTensor<int32_t> &kvValidSizeGm,
                                                const GlobalTensor<KV_T> &kvMergeGm,
                                                const GlobalTensor<KV_T> &keyRopeGm, const GlobalTensor<KV_T> &keyGm,
                                                const GlobalTensor<int32_t> &blkTableGm);
    __aicore__ inline void InitSelectionUpdateGlobalTensor(
        const GlobalTensor<KV_T> &selectionKRopeGm, const GlobalTensor<KV_T> &selectionKvCacheGm,
        const GlobalTensor<int32_t> &selectionKvBlockTableGm,
        const GlobalTensor<int32_t> &selectionKvBlockStatusGm,
        const GlobalTensor<int32_t> &selectionKvActualSeqGm, int64_t selectionKvBlockSize,
        int64_t selectionMaxBlockNum, int64_t selectionTopkBlockSize, bool enableSelectionUpdate);
    __aicore__ inline void InitVec1GlobalTensor(GlobalTensor<MM1_OUT_T> mm1ResGm, GlobalTensor<KV_T> vec1ResGm,
                                                GlobalTensor<int32_t> actualSeqLengthsQGm,
                                                GlobalTensor<int32_t> actualSeqLengthsKVGm, GlobalTensor<T> lseMaxFdGm,
                                                GlobalTensor<T> lseSumFdGm, GlobalTensor<int32_t> topKGm);
    __aicore__ inline void InitVec2GlobalTensor(GlobalTensor<T> accumOutGm, GlobalTensor<UPDATE_T> vec2ResGm,
                                                GlobalTensor<MM2_OUT_T> mm2ResGm, GlobalTensor<OUT_T> attentionOutGm);
    __aicore__ inline void AllocEventID();
    __aicore__ inline void FreeEventID();
    __aicore__ inline void InitSoftmaxDefaultBuffer();
    // ================================Base Vector==========================================
    __aicore__ inline void RowDivs(LocalTensor<float> dstUb, LocalTensor<float> src0Ub, LocalTensor<float> src1Ub,
                                   uint32_t dealRowCount, uint32_t columnCount, uint32_t actualColumnCount);
    __aicore__ inline void RowMuls(LocalTensor<T> dstUb, LocalTensor<T> src0Ub, LocalTensor<T> src1Ub,
                                   uint32_t dealRowCount, uint32_t columnCount, uint32_t actualColumnCount);
    // ================================Vector0==========================================
    __aicore__ inline void MergeKv(const RunInfo &runInfo);
    __aicore__ inline int64_t GetKeyGmOffset(int64_t realS2Idx, const RunInfo &runInfo, int64_t s2IdLimit);
    __aicore__ inline int64_t GetKeyRopeGmOffset(int64_t realS2Idx, const RunInfo &runInfo, int64_t s2IdLimit);
    __aicore__ inline void GetRealS2Idx(int64_t s2GmOffset, int64_t &realS2Idx, int64_t topkGmBaseOffset,
                                        const RunInfo &runInfo);
    __aicore__ inline void CopyInKv(int64_t &mte2Size, int64_t mte3Size, int64_t mergeMte3Idx, int64_t realS2Idx1,
                                    int64_t realS2Idx2, const RunInfo &runInfo);
    __aicore__ inline void CopyOutMrgeResult(int64_t mte2Size, int64_t mte3Size, int64_t s2StartGmOffset,
                                             int64_t mergeMte3Idx, const RunInfo &runInfo);
    __aicore__ inline void CopyOutSelectionUpdate(int64_t mte2Size, int64_t mte3Size, int64_t s2StartGmOffset,
                                                  int64_t mergeMte3Idx, const RunInfo &runInfo);
    __aicore__ inline void CopyOutSelectionUpdateFromKvMerge(const RunInfo &runInfo);
    __aicore__ inline bool IsSelectionUpdateEnabled() const;
    __aicore__ inline bool UseAllCoreSelectionUpdate() const;
    __aicore__ inline bool UsePipelineSelectionUpdate() const;
    __aicore__ inline void RunAllCoreSelectionUpdate();
    __aicore__ inline uint64_t GetActualQSeqLenForSelectionUpdate(uint32_t batchIdx);
    __aicore__ inline uint64_t GetActualKVSeqLenForSelectionUpdate(uint32_t batchIdx);
    __aicore__ inline void CopySelectionUpdateTokenFromFullCache(
        int64_t selectionRow, uint32_t batchIdx, int64_t topkPos, int32_t topkValue, int64_t s2IdLimit);
    __aicore__ inline void UpdateSelectionRange(
        int64_t selectionRow, uint32_t batchIdx, int64_t tokenStart, int64_t tokenEnd, int64_t s2IdLimit,
        bool appendActualSeq = false);
    __aicore__ inline void RefreshSelectionStatusRange(
        int64_t topkBase, int64_t statusBase, int64_t tokenStart, int64_t tokenEnd);
    __aicore__ inline void SetInfInBlk(const LocalTensor<T> &mmResUb, uint32_t dealRowCount, uint32_t columnCount,
                                       uint64_t startId, uint64_t endId);
    __aicore__ inline void SetMidInf(const LocalTensor<T> &mmResUb, uint32_t dealRowCount, uint32_t columnCount,
                                     uint64_t startId, uint64_t endId);
    __aicore__ inline void CopyInSingleKv(int64_t &mte2Size, int64_t mte3Size, int64_t mergeMte3Idx, int64_t realS2Idx,
                                          int64_t keyBNBOffset,int64_t s2IdLimit, const RunInfo &runInfo);
    // ================================Vector1==========================================
    __aicore__ inline void ProcessVec1SingleBuf(const RunInfo &info, const MSplitInfo &mSplitInfo);
    __aicore__ inline void DealBmm1ResBaseBlock(const RunInfo &info, const MSplitInfo &mSplitInfo, uint32_t startRow,
                                                uint32_t dealRowCount, uint32_t columnCount, uint32_t loopId);
    __aicore__ inline void SoftmaxFlashV2Compute(const RunInfo &info, const MSplitInfo &mSplitInfo,
                                                 LocalTensor<T> &mmResUb, LocalTensor<uint8_t> &softmaxTmpUb,
                                                 uint32_t startRow, uint32_t dealRowCount, uint32_t columnCount,
                                                 uint32_t actualColumnCount);
    __aicore__ inline void AmlaVecCompute(const RunInfo &info, const MSplitInfo &mSplitInfo, LocalTensor<T> &mmResUb,
                                          LocalTensor<uint8_t> &softmaxTmpUb, uint32_t startRow, uint32_t dealRowCount,
                                          uint32_t columnCount, uint32_t actualColumnCount);
    __aicore__ inline void ElewiseCompute(const RunInfo &info, const LocalTensor<T> &mmResUb, uint32_t dealRowCount,
                                          uint32_t columnCount);
    __aicore__ inline void ProcessAmlaNupdate(const RunInfo &info, const MSplitInfo &mSplitInfo);
    __aicore__ inline void ComputeLogSumExpAndCopyToGm(const RunInfo &info, const MSplitInfo &mSplitInfo,
                                                       LocalTensor<T> &softmaxSumUb, LocalTensor<T> &softmaxMaxUb);
    // ================================Vecotr2==========================================
    __aicore__ inline void ProcessVec2SingleBuf(const RunInfo &info, const MSplitInfo &mSplitInfo);
    __aicore__ inline void DealBmm2ResBaseBlock(const RunInfo &info, const MSplitInfo &mSplitInfo, uint32_t startRow,
                                                uint32_t dealRowCount, uint32_t columnCount,
                                                uint32_t actualColumnCount);
    __aicore__ inline void ProcessVec2Inner(const RunInfo &info, const MSplitInfo &mSplitInfo, uint32_t mStartRow,
                                            uint32_t mDealSize);
    __aicore__ inline void Bmm2DataCopyOutTrans(const RunInfo &info, LocalTensor<OUT_T> &attenOutUb, uint32_t wsMStart,
                                                uint32_t dealRowCount, uint32_t columnCount,
                                                uint32_t actualColumnCount);
    __aicore__ inline void Bmm2ResCopyOut(const RunInfo &info, LocalTensor<T> &bmm2ResUb, uint32_t wsMStart,
                                          uint32_t dealRowCount, uint32_t columnCount, uint32_t actualColumnCount);
    __aicore__ inline void Bmm2CastAndCopyOut(const RunInfo &info, LocalTensor<T> &bmm2ResUb, uint32_t wsMStart,
                                              uint32_t dealRowCount, uint32_t columnCount, uint32_t actualColumnCount);
    __aicore__ inline void Bmm2FDDataCopyOut(const RunInfo &info, LocalTensor<T> &bmm2ResUb, uint32_t wsMStart,
                                             uint32_t dealRowCount, uint32_t columnCount, uint32_t actualColumnCount);
    __aicore__ inline uint64_t CalcAccumOffset(uint32_t bN2Idx, uint32_t gS1Idx);
    __aicore__ inline void GetConfusionTransposeTiling(int64_t numR, int64_t numC, const uint32_t stackBufferSize,
                                                       const uint32_t typeSize, ConfusionTransposeTiling &tiling);

    // BLOCK和REPEAT的字节数
    static constexpr uint64_t BYTE_BLOCK = 32UL;
    static constexpr uint32_t REPEAT_BLOCK_BYTE = 256U;
    // BLOCK和REPEAT的FP32元素�?
    static constexpr uint32_t FP32_BLOCK_ELEMENT_NUM = BYTE_BLOCK / sizeof(float);
    static constexpr uint32_t FP32_REPEAT_ELEMENT_NUM = REPEAT_BLOCK_BYTE / sizeof(float);
    // repeat stride不能超过256
    static constexpr uint32_t REPEATE_STRIDE_UP_BOUND = 256;

private:
    static constexpr bool PAGE_ATTENTION = FusedSparseAttentionOverlapTraits::pageAttention;
    static constexpr int TEMPLATE_MODE = FusedSparseAttentionOverlapTraits::templateMode;
    static constexpr bool FLASH_DECODE = FusedSparseAttentionOverlapTraits::flashDecode;
    static constexpr FusedSparseAttentionOverlapLayout LAYOUT_T = FusedSparseAttentionOverlapTraits::layout;
    static constexpr FusedSparseAttentionOverlapLayout KV_LAYOUT_T = FusedSparseAttentionOverlapTraits::kvLayout;

    static constexpr uint64_t MERGE_CACHE_GM_BUF_NUM = 4;
    static constexpr uint64_t SYNC_INPUT_BUF1_FLAG = 2;
    static constexpr uint64_t SYNC_INPUT_BUF1_PONG_FLAG = 3;
    static constexpr uint64_t SYNC_INPUT_BUF2_FLAG = 4;
    static constexpr uint64_t SYNC_INPUT_BUF2_PONG_FLAG = 5;
    static constexpr uint64_t SYNC_OUTPUT_BUF1_FLAG = 4;
    static constexpr uint64_t SYNC_OUTPUT_BUF2_FLAG = 5;
    static constexpr uint32_t INPUT1_BUFFER_OFFSET = ConstInfo::BUFFER_SIZE_BYTE_32K;
    static constexpr uint32_t SOFTMAX_TMP_BUFFER_OFFSET = ConstInfo::BUFFER_SIZE_BYTE_1K;
    static constexpr uint32_t BASE_BLOCK_MAX_ELEMENT_NUM = ConstInfo::BUFFER_SIZE_BYTE_32K / sizeof(T);  // 32768/4=8096
    static constexpr uint32_t BLOCK_ELEMENT_NUM = BYTE_BLOCK / sizeof(T);                                // 32/4=8
    static constexpr T FLOAT_E_SCALAR = 8388608;
    static constexpr T LN2 = 0.6931471805599453094172;
    static constexpr T RECIP_OF_LN2 = 1 / LN2;
    static constexpr T SOFTMAX_MIN_NUM = -2e38;

    const FusedSparseAttentionOverlapTilingDataMla *__restrict tilingData;

    uint32_t pingpongFlag = 0U;
    ConstInfo constInfo = {};

    GlobalTensor<int32_t> mm2ResInt32Gm;
    GlobalTensor<MM1_OUT_T> mm1ResGm;
    GlobalTensor<KV_T> vec1ResGm;
    GlobalTensor<T> lseSumFdGm;
    GlobalTensor<T> lseMaxFdGm;

    GlobalTensor<int32_t> actualSeqLengthsQGm;
    GlobalTensor<int32_t> actualSeqLengthsKVGm;
    GlobalTensor<UPDATE_T> vec2ResGm;
    GlobalTensor<MM2_OUT_T> mm2ResGm;
    GlobalTensor<T> accumOutGm;
    GlobalTensor<OUT_T> attentionOutGm;
    GlobalTensor<int32_t> blkTableGm_;

    GlobalTensor<KV_T> kvMergeGm_;
    GlobalTensor<KV_T> keyRopeGm_;
    GlobalTensor<KV_T> keyGm_;
    GlobalTensor<int32_t> topkGm_;
    GlobalTensor<int32_t> kvValidSizeGm_;
    GlobalTensor<KV_T> selectionKRopeGm_;
    GlobalTensor<KV_T> selectionKvCacheGm_;
    GlobalTensor<int32_t> selectionKvBlockTableGm_;
    GlobalTensor<int32_t> selectionKvBlockStatusGm_;
    GlobalTensor<int32_t> selectionKvActualSeqGm_;
    int64_t selectionKvBlockSize_ = 0;
    int64_t selectionMaxBlockNum_ = 0;
    int64_t selectionTopkBlockSize_ = 0;
    bool enableSelectionUpdate_ = false;
    bool useAllCoreSelectionUpdate_ = false;

    // ================================Local Buffer�?===================================
    TBuf<> inputBuff1;            // 32K
    TBuf<> inputBuff2;            // 16K
    TBuf<> outputBuff1;           // 32K
    TBuf<> outputBuff2;           // 4K

    TBuf<> tmpBuff1;              // 32K
    TBuf<> v0ValidSizeBuff;       // 8K

    TBuf<> nValueBuff;
    TBuf<> cofValueBuff;
    TBuf<> aMlaSumBuff;
    TBuf<> softmaxMaxBuff;        // PRE_LOAD_NUM * 2K
    TBuf<> softmaxExpBuff;        // PRE_LOAD_NUM * 2K
    TBuf<> softmaxSumBuff;        // PRE_LOAD_NUM * 2K
    TBuf<> softmaxMaxDefaultBuff; // 2K
    TBuf<> softmaxSumDefaultBuff; // 2K

    LocalTensor<T> softmaxMaxDefaultUb;
    LocalTensor<T> softmaxSumDefaultUb;

    LocalTensor<T> nValueUb;
    LocalTensor<T> cofValueUb;
    LocalTensor<T> aMlaSumUb;
    LocalTensor<T> softmaxMaxUb;
    LocalTensor<T> softmaxSumUb;
    LocalTensor<T> softmaxExpUb;
    LocalTensor<KV_T> kvMergUb_;
    LocalTensor<KV_T> ropeMergUb_;
    LocalTensor<int32_t> v0ValidSizeUb_;
};

template <typename FusedSparseAttentionOverlapTraits> __aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::InitBuffers(TPipe *pipe)
{
    pipe->InitBuffer(inputBuff1, ConstInfo::BUFFER_SIZE_BYTE_32K * 2); // 2:pingpong
    pipe->InitBuffer(inputBuff2, ConstInfo::BUFFER_SIZE_BYTE_8K * 2);  // 2:pingpong
    pipe->InitBuffer(outputBuff1, ConstInfo::BUFFER_SIZE_BYTE_32K);
    pipe->InitBuffer(outputBuff2, ConstInfo::BUFFER_SIZE_BYTE_4K);

    pipe->InitBuffer(tmpBuff1, ConstInfo::BUFFER_SIZE_BYTE_32K);
    pipe->InitBuffer(v0ValidSizeBuff, ConstInfo::BUFFER_SIZE_BYTE_8K);

    // M_MAX = 512/2vector = 256, 256 * sizeof(T) * N_Buffer
    pipe->InitBuffer(nValueBuff, ConstInfo::BUFFER_SIZE_BYTE_1K * constInfo.preLoadNum);
    pipe->InitBuffer(cofValueBuff, ConstInfo::BUFFER_SIZE_BYTE_1K * constInfo.preLoadNum);
    pipe->InitBuffer(aMlaSumBuff, ConstInfo::BUFFER_SIZE_BYTE_1K * constInfo.preLoadNum);

    pipe->InitBuffer(softmaxMaxBuff, ConstInfo::BUFFER_SIZE_BYTE_1K * constInfo.preLoadNum);
    pipe->InitBuffer(softmaxExpBuff, ConstInfo::BUFFER_SIZE_BYTE_1K * constInfo.preLoadNum);
    pipe->InitBuffer(softmaxSumBuff, ConstInfo::BUFFER_SIZE_BYTE_1K * constInfo.preLoadNum);

    pipe->InitBuffer(softmaxMaxDefaultBuff, ConstInfo::BUFFER_SIZE_BYTE_1K);
    pipe->InitBuffer(softmaxSumDefaultBuff, ConstInfo::BUFFER_SIZE_BYTE_1K);

    nValueUb = nValueBuff.Get<T>();
    cofValueUb = cofValueBuff.Get<T>();
    aMlaSumUb = aMlaSumBuff.Get<T>();

    softmaxMaxUb = softmaxMaxBuff.Get<T>();
    softmaxSumUb = softmaxSumBuff.Get<T>();
    softmaxExpUb = softmaxExpBuff.Get<T>();

    softmaxMaxDefaultUb = softmaxMaxDefaultBuff.Get<T>();
    softmaxSumDefaultUb = softmaxSumDefaultBuff.Get<T>();

    kvMergUb_ = inputBuff1.Get<KV_T>();
    ropeMergUb_ = inputBuff2.Get<KV_T>();

    v0ValidSizeUb_ = v0ValidSizeBuff.Get<int32_t>();
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void
FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::InitParams(const struct ConstInfo &constInfo,
                                                 const FusedSparseAttentionOverlapTilingDataMla *__restrict tilingData)
{
    this->constInfo = constInfo;
    this->tilingData = tilingData;
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void
FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::InitMm2ResInt32GmGlobalTensor(GlobalTensor<int32_t> mm2ResInt32Gm)
{
    this->mm2ResInt32Gm = mm2ResInt32Gm;
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::InitVec0GlobalTensor(
    const GlobalTensor<int32_t> &kvValidSizeGm, const GlobalTensor<KV_T> &kvMergeGm,
    const GlobalTensor<KV_T> &keyRopeGm, const GlobalTensor<KV_T> &keyGm, const GlobalTensor<int32_t> &blkTableGm)
{
    this->kvMergeGm_ = kvMergeGm;
    this->keyRopeGm_ = keyRopeGm;
    this->keyGm_ = keyGm;
    this->blkTableGm_ = blkTableGm;
    this->kvValidSizeGm_ = kvValidSizeGm;
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::InitSelectionUpdateGlobalTensor(
    const GlobalTensor<KV_T> &selectionKRopeGm, const GlobalTensor<KV_T> &selectionKvCacheGm,
    const GlobalTensor<int32_t> &selectionKvBlockTableGm,
    const GlobalTensor<int32_t> &selectionKvBlockStatusGm,
    const GlobalTensor<int32_t> &selectionKvActualSeqGm, int64_t selectionKvBlockSize,
    int64_t selectionMaxBlockNum, int64_t selectionTopkBlockSize, bool enableSelectionUpdate)
{
    this->selectionKRopeGm_ = selectionKRopeGm;
    this->selectionKvCacheGm_ = selectionKvCacheGm;
    this->selectionKvBlockTableGm_ = selectionKvBlockTableGm;
    this->selectionKvBlockStatusGm_ = selectionKvBlockStatusGm;
    this->selectionKvActualSeqGm_ = selectionKvActualSeqGm;
    this->selectionKvBlockSize_ = selectionKvBlockSize;
    this->selectionMaxBlockNum_ = selectionMaxBlockNum;
    this->selectionTopkBlockSize_ = selectionTopkBlockSize;
    this->enableSelectionUpdate_ = enableSelectionUpdate;
    this->useAllCoreSelectionUpdate_ = enableSelectionUpdate;
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::InitVec1GlobalTensor(
    GlobalTensor<MM1_OUT_T> mm1ResGm, GlobalTensor<KV_T> vec1ResGm,
    GlobalTensor<int32_t> actualSeqLengthsQGm, GlobalTensor<int32_t> actualSeqLengthsKVGm, GlobalTensor<T> lseMaxFdGm,
    GlobalTensor<T> lseSumFdGm, GlobalTensor<int32_t> topKGm)
{
    this->mm1ResGm = mm1ResGm;
    this->vec1ResGm = vec1ResGm;
    this->actualSeqLengthsQGm = actualSeqLengthsQGm;
    this->actualSeqLengthsKVGm = actualSeqLengthsKVGm;
    this->lseMaxFdGm = lseMaxFdGm;
    this->lseSumFdGm = lseSumFdGm;
    this->topkGm_ = topKGm;
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::InitVec2GlobalTensor(GlobalTensor<T> accumOutGm,
                                                                    GlobalTensor<UPDATE_T> vec2ResGm,
                                                                    GlobalTensor<MM2_OUT_T> mm2ResGm,
                                                                    GlobalTensor<OUT_T> attentionOutGm)
{
    this->accumOutGm = accumOutGm;
    this->vec2ResGm = vec2ResGm;
    this->mm2ResGm = mm2ResGm;
    this->attentionOutGm = attentionOutGm;
}

template <typename FusedSparseAttentionOverlapTraits> __aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::AllocEventID()
{
    SetFlag<AscendC::HardEvent::V_MTE2>(SYNC_INPUT_BUF1_FLAG);
    SetFlag<AscendC::HardEvent::V_MTE2>(SYNC_INPUT_BUF1_PONG_FLAG);
    SetFlag<AscendC::HardEvent::V_MTE2>(SYNC_INPUT_BUF2_FLAG);
    SetFlag<AscendC::HardEvent::V_MTE2>(SYNC_INPUT_BUF2_PONG_FLAG);
    SetFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF1_FLAG);
    SetFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF2_FLAG);
}

template <typename FusedSparseAttentionOverlapTraits> __aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::FreeEventID()
{
    WaitFlag<AscendC::HardEvent::V_MTE2>(SYNC_INPUT_BUF1_FLAG);
    WaitFlag<AscendC::HardEvent::V_MTE2>(SYNC_INPUT_BUF1_PONG_FLAG);
    WaitFlag<AscendC::HardEvent::V_MTE2>(SYNC_INPUT_BUF2_FLAG);
    WaitFlag<AscendC::HardEvent::V_MTE2>(SYNC_INPUT_BUF2_PONG_FLAG);
    WaitFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF1_FLAG);
    WaitFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF2_FLAG);
}

template <typename FusedSparseAttentionOverlapTraits> __aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::InitSoftmaxDefaultBuffer()
{
    Duplicate(softmaxMaxDefaultUb, SOFTMAX_MIN_NUM, SOFTMAX_TMP_BUFFER_OFFSET / sizeof(T));
    Duplicate(softmaxSumDefaultUb, ConstInfo::FLOAT_ZERO, SOFTMAX_TMP_BUFFER_OFFSET / sizeof(T));
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::ComputeLogSumExpAndCopyToGm(const RunInfo &info,
                                                                                         const MSplitInfo &mSplitInfo,
                                                                                         LocalTensor<T> &softmaxSumUb,
                                                                                         LocalTensor<T> &softmaxMaxUb)
{
    if (mSplitInfo.vecDealM == 0) {
        return;
    }
    uint64_t baseOffset = mSplitInfo.nBufferStartM / 2;
    size_t size = mSplitInfo.vecDealM * FP32_BLOCK_ELEMENT_NUM;
    uint64_t accumTmpOutNum = CalcAccumOffset(info.bIdx, info.gS1Idx);
    uint64_t offset = (accumTmpOutNum * constInfo.kvHeadNum * constInfo.mBaseSize +              // taskoffset
                       info.tndCoreStartKVSplitPos * constInfo.kvHeadNum * constInfo.mBaseSize + // 份数offset
                       mSplitInfo.nBufferStartM + mSplitInfo.vecStartM) *
                       FP32_BLOCK_ELEMENT_NUM; // m轴offset
    if (info.actualSingleProcessSInnerSize != 0) {
        LocalTensor<T> tmp = outputBuff2.Get<T>();
        WaitFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF2_FLAG);
        Brcb(tmp, softmaxSumUb[baseOffset], (mSplitInfo.vecDealM + 7) / 8, {1, 8});
        SetFlag<AscendC::HardEvent::V_MTE3>(SYNC_OUTPUT_BUF2_FLAG);
        WaitFlag<AscendC::HardEvent::V_MTE3>(SYNC_OUTPUT_BUF2_FLAG);
        DataCopy(lseSumFdGm[offset], tmp, size);
        SetFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF2_FLAG);

        tmp = outputBuff2.Get<T>();
        WaitFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF2_FLAG);
        Brcb(tmp, softmaxMaxUb[baseOffset], (mSplitInfo.vecDealM + 7) / 8, {1, 8});
        SetFlag<AscendC::HardEvent::V_MTE3>(SYNC_OUTPUT_BUF2_FLAG);
        WaitFlag<AscendC::HardEvent::V_MTE3>(SYNC_OUTPUT_BUF2_FLAG);
        DataCopy(lseMaxFdGm[offset], tmp, size);
        SetFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF2_FLAG);
    } else {
        matmul::InitOutput<T>(lseSumFdGm[offset], size, ConstInfo::FLOAT_ZERO);
        matmul::InitOutput<T>(lseMaxFdGm[offset], size, SOFTMAX_MIN_NUM);
    }
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::ElewiseCompute(const RunInfo &info,
                                                                            const LocalTensor<T> &mmResUb,
                                                                            uint32_t dealRowCount, uint32_t columnCount)
{
    Muls(mmResUb, mmResUb, static_cast<T>(tilingData->baseParams.scaleValue), dealRowCount * columnCount);
    if constexpr (TEMPLATE_MODE == V_TEMPLATE) {
        // v0的无效值判�?
        uint64_t s2ValidSizeFirstPart = v0ValidSizeUb_.GetValue(128 + info.loop % MERGE_CACHE_GM_BUF_NUM);
        uint64_t s2ValidSizeSecondPart = v0ValidSizeUb_.GetValue(256 + info.loop % MERGE_CACHE_GM_BUF_NUM);

        int64_t s2ProcessSize = info.actualSingleProcessSInnerSize;
        int64_t s2Pair = CeilDiv(s2ProcessSize, 2L * constInfo.sparseBlockSize);
        int64_t s2Mid = CeilDiv(s2Pair, 2L) * 2 * constInfo.sparseBlockSize;
        if (s2Mid > s2ProcessSize) {
            s2Mid = s2ProcessSize;
        }
        if (unlikely(s2ValidSizeFirstPart < s2Mid)) {
            int64_t s2StartCeilAlign = CeilAlign(s2ValidSizeFirstPart, 8);
            int64_t s2MidFloorAlign = s2Mid / 8 * 8;
            // 场景一 s2Mid > s2ValidSizeFirstPart + oneBlk
            // 可以推导出s2StartCeilAlign < s2Mid   第一阶段取到s2StartCeilAlign
            // s2StartCeilAlign <= s2MidFloorAlign 第二阶段取到s2MidFloorAlign
            // 场景�?s2Mid <= s2ValidSizeFirstPart + oneBlk 
            // 可以推导�?s2StartCeilAlign >= s2Mid 第一阶段取到mid
            // s2StartCeilAlign > s2MidFloorAlign 第二阶段取到s2StartCeilAlign
            SetInfInBlk(mmResUb, dealRowCount, columnCount, s2ValidSizeFirstPart,
                        s2StartCeilAlign >= s2Mid ? s2Mid : s2StartCeilAlign);
            SetMidInf(mmResUb, dealRowCount, columnCount, s2StartCeilAlign, s2MidFloorAlign);
            SetInfInBlk(mmResUb, dealRowCount, columnCount,
                        s2StartCeilAlign <= s2MidFloorAlign ? s2MidFloorAlign : s2StartCeilAlign, s2Mid);
        }
        if (unlikely(s2ValidSizeSecondPart < s2ProcessSize - s2Mid)) {
            // 场景一 s2Mid + s2ValidSizeSecondPart > s2ProcessSize + oneBlk
            // 可以推导�?s2StartCeilAlign < s2ProcessSize 第一阶段取到s2StartCeilAlign
            // s2StartCeilAlign <= s2EndFloorAlign 第二阶段取到s2EndFloorAlign
            // 场景�?s2Mid + s2ValidSizeSecondPart <= s2ProcessSize + oneBlk
            // 可以推导�?s2StartCeilAlign >= s2ProcessSize 第一阶段取到s2ProcessSize
            // s2StartCeilAlign > s2EndFloorAlign 第二阶段取到s2StartCeilAlign
            int64_t s2StartCeilAlign = CeilAlign(s2Mid + s2ValidSizeSecondPart, 8);
            int64_t s2EndFloorAlign = s2ProcessSize / 8 * 8;
            SetInfInBlk(mmResUb, dealRowCount, columnCount, s2Mid + s2ValidSizeSecondPart,
                        s2StartCeilAlign >= s2ProcessSize ? s2ProcessSize : s2StartCeilAlign);
            SetMidInf(mmResUb, dealRowCount, columnCount, s2StartCeilAlign, s2EndFloorAlign);
            SetInfInBlk(mmResUb, dealRowCount, columnCount,
                        s2StartCeilAlign <= s2EndFloorAlign ? s2EndFloorAlign : s2StartCeilAlign, s2ProcessSize);
        }
    }
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::SetInfInBlk(const LocalTensor<T> &mmResUb,
                                                                         uint32_t dealRowCount, uint32_t columnCount,
                                                                         uint64_t startId, uint64_t endId)
{
    //       startId     endId
    // x x x   0      0   0     x x x
    // 从startId到endId部分�?inf, endId、startId为endId一个blk内部的下�?
    if (startId >= endId) {
        return;
    }

    uint64_t startFloorAlignSize = startId / BLOCK_ELEMENT_NUM * BLOCK_ELEMENT_NUM;
    uint64_t notComputePreMaskOneBlk = (1 << (startId - startFloorAlignSize)) - 1;
    uint64_t notComputePostMaskOneBlk = ~((1 << (endId - startFloorAlignSize)) - 1);
    uint64_t notComputeMaskOneBlk = notComputePreMaskOneBlk ^ notComputePostMaskOneBlk;

    uint64_t maskOneBlk = ~notComputeMaskOneBlk;
    uint64_t mask[1] = {maskOneBlk};
    for (int i = 1; i < 8; i++) {
        mask[0] = mask[0] | (maskOneBlk << (i * 8));
    }
    for (uint64_t rowId = 0; rowId < dealRowCount; rowId += 8) {
        Duplicate(mmResUb[rowId * columnCount + startFloorAlignSize], SOFTMAX_MIN_NUM, mask,
                  1, CeilDiv(columnCount, 8), 0);
    }
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::SetMidInf(const LocalTensor<T> &mmResUb,
                                                                       uint32_t dealRowCount, uint32_t columnCount,
                                                                       uint64_t startId, uint64_t endId)
{
    if (startId >= endId) {
        return;
    }
    // startId        endId
    //    0      ...    0
    // 从startId到endId部分�?inf, startId、endId�?2B对齐的下�?
    for (uint64_t rowId = 0; rowId < dealRowCount; rowId++) {
        Duplicate(mmResUb[rowId * columnCount + startId], SOFTMAX_MIN_NUM, endId - startId);
    }
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::SoftmaxFlashV2Compute(
    const RunInfo &info, const MSplitInfo &mSplitInfo, LocalTensor<T> &mmResUb, LocalTensor<uint8_t> &softmaxTmpUb,
    uint32_t startRow, uint32_t dealRowCount, uint32_t columnCount, uint32_t actualColumnCount)
{
    LocalTensor<T> inSumTensor;
    LocalTensor<T> inMaxTensor;
    uint32_t baseOffset = mSplitInfo.nBufferStartM / 2 + startRow;
    uint32_t outIdx = info.loop % (constInfo.preLoadNum);
    uint32_t softmaxOutOffset = outIdx * SOFTMAX_TMP_BUFFER_OFFSET / sizeof(T) + baseOffset;
    if (info.isFirstSInnerLoop) {
        inMaxTensor = softmaxMaxDefaultUb;
        inSumTensor = softmaxSumDefaultUb;
    } else {
        uint32_t inIdx = (info.loop - 1) % (constInfo.preLoadNum);
        inMaxTensor = softmaxMaxUb[inIdx * SOFTMAX_TMP_BUFFER_OFFSET / sizeof(T) + baseOffset];
        inSumTensor = softmaxSumUb[inIdx * SOFTMAX_TMP_BUFFER_OFFSET / sizeof(T) + baseOffset];
    }
    if (actualColumnCount !=0) {
        SoftMaxShapeInfo srcShape{dealRowCount, columnCount, dealRowCount, actualColumnCount};
        SoftMaxTiling newTiling =
            SoftMaxFlashV2TilingFunc(srcShape, sizeof(T), sizeof(T), softmaxTmpUb.GetSize(), true, false);
        SoftmaxFlashV2<T, true, true, false, false, FUSED_SPARSE_ATTENTION_OVERLAP_SOFTMAX_FLASHV2_CFG_WITHOUT_BRC>(
        mmResUb, softmaxSumUb[softmaxOutOffset], softmaxMaxUb[softmaxOutOffset], mmResUb,
        softmaxExpUb[softmaxOutOffset], inSumTensor, inMaxTensor, softmaxTmpUb, newTiling, srcShape);
    } else {
        uint32_t dealRowCountAlign = FusedSparseAttentionOverlapAlign(dealRowCount, FP32_BLOCK_ELEMENT_NUM);
        DataCopy(softmaxSumUb[softmaxOutOffset], inSumTensor, dealRowCountAlign);
        pipe_barrier(PIPE_V);
        DataCopy(softmaxMaxUb[softmaxOutOffset], inMaxTensor, dealRowCountAlign);
    }
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::AmlaVecCompute(
    const RunInfo &info, const MSplitInfo &mSplitInfo, LocalTensor<T> &mmResUb, LocalTensor<uint8_t> &softmaxTmpUb,
    uint32_t startRow, uint32_t dealRowCount, uint32_t columnCount, uint32_t actualColumnCount)
{
    uint32_t baseOffset = mSplitInfo.nBufferStartM / 2 + startRow;
    uint32_t calCount = dealRowCount;
    uint32_t outIdx = info.loop % (constInfo.preLoadNum);
    uint32_t softmaxOutOffset = outIdx * SOFTMAX_TMP_BUFFER_OFFSET / sizeof(T) + baseOffset;
    // compute n(i)
    LocalTensor<T> nTmp = softmaxTmpUb.template ReinterpretCast<T>();
    LocalTensor<T> nUpdateTmp = nTmp[SOFTMAX_TMP_BUFFER_OFFSET / sizeof(T)];
    Muls(nTmp, softmaxMaxUb[softmaxOutOffset], ((T)(-1.0)) * RECIP_OF_LN2, calCount);

    pipe_barrier(PIPE_V);
    Cast(nTmp, nTmp, RoundMode::CAST_ROUND, calCount);
    pipe_barrier(PIPE_V);

    uint32_t prOutIdx = (info.loop - 1) % (constInfo.preLoadNum);
    uint32_t PreSoftmaxOutOffset = prOutIdx * SOFTMAX_TMP_BUFFER_OFFSET / sizeof(T) + baseOffset;
    // n(i) - n(i-1)
    if (info.isFirstSInnerLoop) {
        Duplicate(nUpdateTmp, ConstInfo::FLOAT_ZERO, calCount); // n1=n0
    } else {
        Sub(nUpdateTmp, nTmp, nValueUb[PreSoftmaxOutOffset], calCount);
    }
    pipe_barrier(PIPE_V);
    // update n(i), DataCopy not support when calCount is not align 32B, so use Adds
    Adds(nValueUb[softmaxOutOffset], nTmp, ConstInfo::FLOAT_ZERO, calCount);
    pipe_barrier(PIPE_V);

    // update softmax res
    LocalTensor<T> nUpdateTmp2 = nTmp[2 * SOFTMAX_TMP_BUFFER_OFFSET / sizeof(T)];
    LocalTensor<KV_T> nTmp_KvT = nTmp[3 * SOFTMAX_TMP_BUFFER_OFFSET / sizeof(T)].template ReinterpretCast<KV_T>();
    LocalTensor<T> tmpCofUb = nTmp[4 * SOFTMAX_TMP_BUFFER_OFFSET / sizeof(T)];
    LocalTensor<T> epsUb = nTmp[5 * SOFTMAX_TMP_BUFFER_OFFSET / sizeof(T)];
    Muls(nUpdateTmp2, softmaxMaxUb[softmaxOutOffset], RECIP_OF_LN2, calCount);
    pipe_barrier(PIPE_V);
    Add(nTmp, nUpdateTmp2, nTmp, calCount);
    pipe_barrier(PIPE_V);
    Muls(nTmp, nTmp, LN2, calCount);
    pipe_barrier(PIPE_V);
    Exp(nTmp, nTmp, calCount);
    pipe_barrier(PIPE_V);
    Cast(nTmp_KvT, nTmp, RoundMode::CAST_ROUND, calCount);       // fp32->fp16/bf16
    pipe_barrier(PIPE_V);
    Cast(nUpdateTmp2, nTmp_KvT, RoundMode::CAST_NONE, calCount); // fp16/bf16->fp32
    pipe_barrier(PIPE_V);
    if (info.s2Idx + 1 == info.curSInnerLoopTimes) {
        Mul(aMlaSumUb[softmaxOutOffset], softmaxSumUb[softmaxOutOffset], nUpdateTmp2, calCount);
    }
    if (actualColumnCount == 0) {
        WaitFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF2_FLAG);
        SetFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF2_FLAG);
        return;
    }
    LocalTensor<T> nTmp3 = nTmp[6 * SOFTMAX_TMP_BUFFER_OFFSET / sizeof(T)];
    Brcb(nTmp3, nUpdateTmp2, (dealRowCount + 7) / 8, {1, 8});
    pipe_barrier(PIPE_V);
    RowMuls(mmResUb, mmResUb, nTmp3, dealRowCount, columnCount, actualColumnCount);

    Div(tmpCofUb, nTmp, nUpdateTmp2, calCount); // cof(i)=tmpS32/tmpS16
    if (info.isFirstSInnerLoop) {
        Duplicate(cofValueUb[softmaxOutOffset], (T)1.0, calCount);       // cof_0=1
        pipe_barrier(PIPE_V);
        Div(epsUb, cofValueUb[softmaxOutOffset], tmpCofUb, calCount);    // 1 / cof(i)
    } else {
        pipe_barrier(PIPE_V);
        Div(epsUb, cofValueUb[PreSoftmaxOutOffset], tmpCofUb, calCount); // cof(i - 1) / cof(i)
    }
    pipe_barrier(PIPE_V);

    Adds(cofValueUb[softmaxOutOffset], tmpCofUb, ConstInfo::FLOAT_ZERO, calCount); // store cof(i)
    Adds(epsUb, epsUb, (T)(-1.0), calCount); // cof(i - 1) / cof(i) - 1
    pipe_barrier(PIPE_V);
    Muls(epsUb, epsUb, (T)1.5, calCount);    // (cof(i - 1) - cof(i)) / cof(i) * 1.5

    Maxs(nUpdateTmp, nUpdateTmp, (T)(-30.0), calCount); // N = max(n(i) - n(i-1), -30)
    pipe_barrier(PIPE_V);
    Adds(epsUb, epsUb, (T)(0.000001), calCount);
    pipe_barrier(PIPE_V);
    Add(nUpdateTmp, nUpdateTmp, epsUb, calCount);
    pipe_barrier(PIPE_V);
    Muls(nUpdateTmp, nUpdateTmp, FLOAT_E_SCALAR, calCount); // N = N * pow(2, 23)
    pipe_barrier(PIPE_V);

    // nUpdate int32 out
    LocalTensor<int32_t> tmQue = outputBuff2.Get<int32_t>();
    WaitFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF2_FLAG);
    LocalTensor<int32_t> nInt32Out = tmQue[startRow]; // 缓存nUpdate

    Cast(nInt32Out, nUpdateTmp, RoundMode::CAST_ROUND, dealRowCount);
    pipe_barrier(PIPE_V);

    SetFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF2_FLAG);
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::DealBmm1ResBaseBlock(
    const RunInfo &info, const MSplitInfo &mSplitInfo, uint32_t startRow, uint32_t dealRowCount,
    uint32_t columnCount, uint32_t loopId)
{
    uint32_t computeSize = dealRowCount * columnCount;
    uint64_t inOutGmOffset = (info.loop % constInfo.preLoadNum) * constInfo.mmResUbSize +
                             (mSplitInfo.nBufferStartM + mSplitInfo.vecStartM + startRow) * columnCount;
    LocalTensor<MM1_OUT_T> mmResUb = inputBuff1.Get<MM1_OUT_T>();
    mmResUb = mmResUb[pingpongFlag * INPUT1_BUFFER_OFFSET / sizeof(MM1_OUT_T)];
    WaitFlag<AscendC::HardEvent::V_MTE2>(SYNC_INPUT_BUF1_FLAG + pingpongFlag);

    DataCopy(mmResUb, mm1ResGm[inOutGmOffset], computeSize);
    if constexpr (TEMPLATE_MODE == V_TEMPLATE) {
        if (loopId == 0) {
            WaitFlag<HardEvent::MTE2_S>(0);
        }
    }
    SetFlag<AscendC::HardEvent::MTE2_V>(SYNC_INPUT_BUF1_FLAG);
    WaitFlag<AscendC::HardEvent::MTE2_V>(SYNC_INPUT_BUF1_FLAG);

    ElewiseCompute(info, mmResUb, dealRowCount, columnCount);

    pipe_barrier(PIPE_V);
    LocalTensor<T> tmpAFloorUb = tmpBuff1.Get<T>();
    LocalTensor<uint8_t> softmaxTmpUb = tmpAFloorUb.template ReinterpretCast<uint8_t>();

    SoftmaxFlashV2Compute(info, mSplitInfo, mmResUb, softmaxTmpUb, startRow, dealRowCount, columnCount,
                            info.actualSingleProcessSInnerSize);

    pipe_barrier(PIPE_V);
    AmlaVecCompute(info, mSplitInfo, mmResUb, softmaxTmpUb, startRow, dealRowCount, columnCount,
                    info.actualSingleProcessSInnerSize);

    pipe_barrier(PIPE_V);
    LocalTensor<KV_T> tmpMMResCastTensor = outputBuff1.Get<KV_T>();
    WaitFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF1_FLAG);

    Cast(tmpMMResCastTensor, mmResUb, AscendC::RoundMode::CAST_ROUND, computeSize);
    SetFlag<AscendC::HardEvent::V_MTE2>(SYNC_INPUT_BUF1_FLAG + pingpongFlag);

    SetFlag<AscendC::HardEvent::V_MTE3>(SYNC_OUTPUT_BUF1_FLAG);
    WaitFlag<AscendC::HardEvent::V_MTE3>(SYNC_OUTPUT_BUF1_FLAG);
    DataCopy(vec1ResGm[inOutGmOffset], tmpMMResCastTensor, computeSize);
    SetFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF1_FLAG);
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::ProcessAmlaNupdate(const RunInfo &info, const MSplitInfo &mSplitInfo)
{
    if (mSplitInfo.vecDealM == 0) {
        return;
    }
    if (info.isFirstSInnerLoop) {
        return;
    }

    LocalTensor<int32_t> nUpdateTensor = outputBuff2.Get<int32_t>(); // shape:1/2*s1*g
    WaitFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF2_FLAG);
    SetFlag<AscendC::HardEvent::V_MTE3>(SYNC_OUTPUT_BUF2_FLAG);
    WaitFlag<AscendC::HardEvent::V_MTE3>(SYNC_OUTPUT_BUF2_FLAG);

    constexpr uint32_t dGroupSize = 128U;
    constexpr uint32_t mSplitSize = 64U;     // tmpQue size 32KB，一次只能处�?4个N，最大保存的数据大小�?4*128*sizeof(int32)
    constexpr uint32_t ONE_BLOCK_SIZE = 32U; // 32B

    uint32_t subMSize = FusedSparseAttentionOverlapAlign(mSplitInfo.vecDealM, 16U);
    uint16_t elementPerBlock = ONE_BLOCK_SIZE / sizeof(int32_t);      // 单个datablock的元素数，int32_t类型的为32/4=8
    uint32_t loopCount = (subMSize + mSplitSize - 1) / mSplitSize;
    uint32_t tailSplitSize = subMSize - (loopCount - 1) * mSplitSize; // 尾块

    for (uint32_t loop = 0, processMSize = mSplitSize; loop < loopCount; loop++) {
        if (loop == (loopCount - 1)) {
            processMSize = tailSplitSize;
        }
        LocalTensor<int32_t> tmpQue = outputBuff1.Get<int32_t>();

        WaitFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF1_FLAG);
        // (m,1)单次brcb扩充�?m,8), 重复16�? 扩充�?m,128)
        for (uint32_t i = 0; i < dGroupSize / elementPerBlock; i++) {
            Brcb(tmpQue[i * elementPerBlock],
                 nUpdateTensor[loop * mSplitSize], 
                 static_cast<uint8_t>((processMSize + elementPerBlock - 1) / elementPerBlock),
                 {static_cast<uint16_t>(dGroupSize / elementPerBlock), // 单次迭代内，目的操作数不同datablock间地址步长,单位为datablock
                  static_cast<uint16_t>(dGroupSize)});                 // 相邻迭代间，目的操作数相同datablock地址步长
        }

        SetFlag<AscendC::HardEvent::V_MTE3>(SYNC_OUTPUT_BUF1_FLAG);
        WaitFlag<AscendC::HardEvent::V_MTE3>(SYNC_OUTPUT_BUF1_FLAG);

        uint64_t baseoffset = (info.bn2IdxInCurCore % constInfo.preLoadNum) * constInfo.bmm2ResUbSize +
                              (mSplitInfo.nBufferStartM + mSplitInfo.vecStartM + loop * mSplitSize) * constInfo.headDim;

        SetAtomicAdd<int32_t>();
        DataCopyParams dataCopyParams;
        dataCopyParams.blockCount = static_cast<uint16_t>(processMSize);
        dataCopyParams.blockLen = dGroupSize * sizeof(int32_t) / ONE_BLOCK_SIZE; // 每个block�?28个元素，单位�?2B
        dataCopyParams.srcStride = 0;                                            // 前面一个数据块的尾与后面数据块的头的间�?
        dataCopyParams.dstStride = static_cast<uint16_t>((constInfo.headDim - dGroupSize) *
                                                         sizeof(int32_t) / ONE_BLOCK_SIZE); // 单位�?2B
        for (uint32_t i = 0; i < constInfo.headDim / dGroupSize; i++) {          // 4=512/128
            DataCopy(mm2ResInt32Gm[baseoffset + i * dGroupSize] ,tmpQue, dataCopyParams);
        }
        SetAtomicNone();
        SetFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF1_FLAG);
    }
    SetFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF2_FLAG);
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::ProcessVec1SingleBuf(const RunInfo &info,
                                                                                  const MSplitInfo &mSplitInfo)
{
    if (mSplitInfo.vecDealM == 0) {
        return;
    }
    uint32_t mSplitSize = info.actualSingleProcessSInnerSize == 0 ?
        16 : BASE_BLOCK_MAX_ELEMENT_NUM / info.actualSingleProcessSInnerSizeAlign;
    // 1. 向下8对齐是因为UB操作至少32B
    // 2. info.actualSingleProcessSInnerSizeAlign最�?12, mSplitSize可以确保最小为16
    mSplitSize = mSplitSize / 8 * 8;

    if (mSplitSize > mSplitInfo.vecDealM) {
        mSplitSize = mSplitInfo.vecDealM;
    }
    uint32_t loopCount = (mSplitInfo.vecDealM + mSplitSize - 1) / mSplitSize;
    uint32_t tailSplitSize = mSplitInfo.vecDealM - (loopCount - 1) * mSplitSize;

    if constexpr (TEMPLATE_MODE == V_TEMPLATE) {
        DataCopyExtParams dataCopyParams;
        dataCopyParams.blockCount = 1;
        dataCopyParams.blockLen = 256 * sizeof(int32_t);
        dataCopyParams.srcStride = 0;
        dataCopyParams.dstStride = 0;
        DataCopyPadExtParams<int32_t> padParams;
        // 额外偏移128个元素，避免不同loop下v0和v1互相影响
        DataCopyPad(v0ValidSizeUb_[128], kvValidSizeGm_[info.loop % MERGE_CACHE_GM_BUF_NUM * (128 * 2)],
                    dataCopyParams, padParams);
        SetFlag<HardEvent::MTE2_S>(0);
        if (unlikely(loopCount == 0)) {
            // scalar同步影响较大，挪到循环内部进�?
            WaitFlag<HardEvent::MTE2_S>(0);
        }
    }
    for (uint32_t i = 0, dealSize = mSplitSize; i < loopCount; i++) {
        if (i == (loopCount - 1)) {
            dealSize = tailSplitSize;
        }
        DealBmm1ResBaseBlock(info, mSplitInfo, i * mSplitSize, dealSize, info.actualSingleProcessSInnerSizeAlign, i);
        pingpongFlag ^= 1; // pingpong 0 1切换
    }
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::GetRealS2Idx(int64_t s2GmOffset, int64_t &realS2Idx,
                                                            int64_t topkGmBaseOffset, const RunInfo &runInfo)
{
    int64_t topkGmIdx = (s2GmOffset + runInfo.s2Idx * constInfo.s2BaseSize) / constInfo.sparseBlockSize;
    if (unlikely(topkGmIdx >= constInfo.sparseBlockCount)) {
        realS2Idx = -1;
        return;
    }
    realS2Idx = topkGm_.GetValue(topkGmBaseOffset + topkGmIdx) * static_cast<int64_t>(constInfo.sparseBlockSize) +
                static_cast<int64_t>((s2GmOffset + runInfo.s2Idx * constInfo.s2BaseSize) % constInfo.sparseBlockSize);
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline int64_t FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::GetKeyGmOffset(int64_t realS2Idx,
                                                                 const RunInfo &runInfo, int64_t s2IdLimit)
{
    if (realS2Idx < 0 || realS2Idx >= s2IdLimit) {
        return -1;
    }
    int64_t realKeyGmOffset = 0;
    if constexpr (PAGE_ATTENTION) {
        int64_t blkTableIdx = realS2Idx / constInfo.kvCacheBlockSize;
        int64_t blkTableOffset = realS2Idx % constInfo.kvCacheBlockSize;
        realKeyGmOffset = blkTableGm_.GetValue(runInfo.bIdx * constInfo.maxBlockNumPerBatch + blkTableIdx) *
                                static_cast<int64_t>(constInfo.kvCacheBlockSize) *
                                static_cast<int64_t>(constInfo.kvHeadNum) +
                                blkTableOffset;
    } else {
        realKeyGmOffset = (runInfo.tensorBOffset +
                           realS2Idx * constInfo.kvHeadNum * constInfo.headDim) /
                           constInfo.headDim;
    }
    return realKeyGmOffset;
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline int64_t FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::GetKeyRopeGmOffset(int64_t realS2Idx,
                                                                 const RunInfo &runInfo, int64_t s2IdLimit)
{
    if (realS2Idx < 0 || realS2Idx >= s2IdLimit) {
        return -1;
    }
    int64_t realKeyRopeGmOffset = 0;
    realKeyRopeGmOffset = (runInfo.tensorBRopeOffset +
                           realS2Idx * constInfo.kvHeadNum * constInfo.headDimRope) /
                           constInfo.headDimRope;
    return realKeyRopeGmOffset;
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void
FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::CopyInSingleKv(int64_t &mte2Size, int64_t mte3Size, int64_t mergeMte3Idx, int64_t realS2Idx,
                                       int64_t keyBNBOffset,int64_t s2IdLimit, const RunInfo &runInfo)
{
    if (keyBNBOffset < 0) {
        return;
    }
    int64_t validS2Count =
        (realS2Idx + constInfo.sparseBlockSize > s2IdLimit ? s2IdLimit - realS2Idx : constInfo.sparseBlockSize);
    DataCopyExtParams intriParams;
    intriParams.blockLen = validS2Count * constInfo.headDim * sizeof(KV_T);
    intriParams.blockCount = 1;
    intriParams.dstStride = 0;
    intriParams.srcStride = 0;
    DataCopyPadExtParams<KV_T> padParams;
    DataCopyPad(kvMergUb_[mergeMte3Idx % 2 * 32 * 512 + (mte2Size - mte3Size) * constInfo.headDim],
                keyGm_[keyBNBOffset * constInfo.headDim], intriParams, padParams);
    intriParams.blockLen = validS2Count * constInfo.headDimRope * sizeof(KV_T);

    DataCopyPad(ropeMergUb_[mergeMte3Idx % 2 * 32 * 64 + (mte2Size - mte3Size) * constInfo.headDimRope],
                keyRopeGm_[keyBNBOffset * constInfo.headDimRope], intriParams, padParams);
    mte2Size += validS2Count;
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::CopyInKv(int64_t &mte2Size, int64_t mte3Size, int64_t mergeMte3Idx,
                                                        int64_t realS2Idx1, int64_t realS2Idx2, const RunInfo &runInfo)
{
    int64_t s2IdLimit = runInfo.curActualSeqLenOri;
    if (constInfo.sparseMode == 3) {
        s2IdLimit = runInfo.curActualSeqLenOri - runInfo.actS1Size + runInfo.gS1Idx / constInfo.gSize + 1;
    }

    int64_t keyOffset1 = GetKeyGmOffset(realS2Idx1, runInfo, s2IdLimit);
    int64_t keyOffset2 = GetKeyGmOffset(realS2Idx2, runInfo, s2IdLimit);
    if (unlikely(keyOffset1 < 0 && keyOffset2 < 0)) {
        return;
    }

    int64_t keySrcStride = 0;
    int64_t keyRopeSrcStride = 0;
    if constexpr (PAGE_ATTENTION) {
        int64_t blkTableSrcStride =
        ((keyOffset1 > keyOffset2 ? (keyOffset1 - keyOffset2) :
        (keyOffset2 - keyOffset1)) - constInfo.sparseBlockSize);
        keySrcStride = blkTableSrcStride * constInfo.headDim * sizeof(KV_T);
        keyRopeSrcStride = blkTableSrcStride * constInfo.headDimRope * sizeof(KV_T);
    } else {
        int64_t keyRopeOffset1 = GetKeyRopeGmOffset(realS2Idx1, runInfo, s2IdLimit);
        int64_t keyRopeOffset2 = GetKeyRopeGmOffset(realS2Idx2, runInfo, s2IdLimit);
        keySrcStride = ((keyOffset1 > keyOffset2 ? (keyOffset1 - keyOffset2) :
                        (keyOffset2 - keyOffset1)) - constInfo.sparseBlockSize) * constInfo.headDim * sizeof(KV_T);
        keyRopeSrcStride = ((keyRopeOffset1 > keyRopeOffset2 ? (keyRopeOffset1 - keyRopeOffset2) :
                            (keyRopeOffset2 - keyRopeOffset1)) - constInfo.sparseBlockSize) *
                             constInfo.headDimRope * sizeof(KV_T);
    }
    
    if (unlikely(keySrcStride >= INT32_MAX || keySrcStride < 0 ||
        (!PAGE_ATTENTION && (keyRopeSrcStride >= INT32_MAX || keyRopeSrcStride < 0)) ||
        realS2Idx1 + constInfo.sparseBlockSize >= s2IdLimit ||
        realS2Idx2 + constInfo.sparseBlockSize >= s2IdLimit)) {
        // stride溢出、stride为负数、s2超长等异常场景，还原�?条搬运指�?
        CopyInSingleKv(mte2Size, mte3Size, mergeMte3Idx, realS2Idx1, keyOffset1, s2IdLimit, runInfo);
        CopyInSingleKv(mte2Size, mte3Size, mergeMte3Idx, realS2Idx2, keyOffset2, s2IdLimit, runInfo);
    } else {
        DataCopyExtParams intriParams;
        intriParams.blockLen = constInfo.sparseBlockSize * constInfo.headDim * sizeof(KV_T);
        intriParams.blockCount = (keyOffset1 >= 0) + (keyOffset2 >= 0);
        intriParams.dstStride = 0;
        intriParams.srcStride = keySrcStride;
        DataCopyPadExtParams<KV_T> padParams;

        int64_t startGmOffset = keyOffset1 > -1 ? keyOffset1 : keyOffset2;
        if (keyOffset2 > -1 && keyOffset2 < keyOffset1) {
            startGmOffset = keyOffset2;
        }
        DataCopyPad(kvMergUb_[mergeMte3Idx % 2 * 32 * 512 + (mte2Size - mte3Size) * constInfo.headDim],
                    keyGm_[startGmOffset * constInfo.headDim], intriParams, padParams);

        intriParams.blockLen = constInfo.sparseBlockSize * constInfo.headDimRope * sizeof(KV_T);
        intriParams.dstStride = 0;
        intriParams.srcStride = keyRopeSrcStride;
        DataCopyPad(ropeMergUb_[mergeMte3Idx % 2 * 32 * 64 + (mte2Size - mte3Size) * constInfo.headDimRope],
                    keyRopeGm_[startGmOffset * constInfo.headDimRope], intriParams, padParams);
        mte2Size += ((keyOffset1 > -1) + (keyOffset2 > -1)) * constInfo.sparseBlockSize;
    }
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::CopyOutMrgeResult(int64_t mte2Size, int64_t mte3Size,
                                                                 int64_t s2GmStartOffset, int64_t mergeMte3Idx,
                                                                 const RunInfo &runInfo)
{
    if (mte2Size <= mte3Size) {
        return;
    }
    SetFlag<AscendC::HardEvent::MTE2_MTE3>(0);
    WaitFlag<AscendC::HardEvent::MTE2_MTE3>(0);

    DataCopyExtParams dataCopyParams;
    dataCopyParams.blockCount = mte2Size - mte3Size;
    dataCopyParams.blockLen = constInfo.headDim * sizeof(KV_T);
    dataCopyParams.srcStride = 0;
    dataCopyParams.dstStride = 0;

    DataCopyPad(kvMergeGm_[runInfo.loop % 4 * 512 * 576 + (s2GmStartOffset + mte3Size)*constInfo.headDim],
                kvMergUb_[mergeMte3Idx % 2 * 32 * 512], dataCopyParams);

    dataCopyParams.blockLen = constInfo.headDimRope * sizeof(KV_T);
    DataCopyPad(kvMergeGm_[runInfo.loop % 4 * 512 * 576 + 512 * 512 + (s2GmStartOffset + mte3Size) *
                constInfo.headDimRope], ropeMergUb_[mergeMte3Idx % 2 * 32 * 64], dataCopyParams);

    (void)runInfo;
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::CopyOutSelectionUpdate(
    int64_t mte2Size, int64_t mte3Size, int64_t s2StartGmOffset, int64_t mergeMte3Idx, const RunInfo &runInfo)
{
    if (mte2Size <= mte3Size || selectionKvBlockSize_ <= 0 || selectionMaxBlockNum_ <= 0 ||
        selectionTopkBlockSize_ != 1 || constInfo.sparseBlockSize != 1) {
        return;
    }

    int64_t tokenCount = mte2Size - mte3Size;
    int64_t logicalSparseOffset =
        static_cast<int64_t>(runInfo.s2Idx) * static_cast<int64_t>(constInfo.s2BaseSize) +
        s2StartGmOffset + mte3Size;
    int64_t qTokenOffset = 0;
    if constexpr (LAYOUT_T == FusedSparseAttentionOverlapLayout::TND) {
        uint64_t actualSeqQPrefixSum =
            (runInfo.bIdx <= 0) ? 0 : actualSeqLengthsQGm.GetValue(runInfo.bIdx - 1);
        qTokenOffset = static_cast<int64_t>(actualSeqQPrefixSum) +
                       static_cast<int64_t>(runInfo.gS1Idx / constInfo.gSize);
    } else {
        qTokenOffset = static_cast<int64_t>(runInfo.bIdx) * static_cast<int64_t>(constInfo.qSeqSize) +
                       static_cast<int64_t>(runInfo.gS1Idx / constInfo.gSize);
    }
    int64_t selectionRow =
        qTokenOffset * static_cast<int64_t>(constInfo.kvHeadNum) + static_cast<int64_t>(runInfo.n2Idx);

    int64_t copiedCount = 0;
    while (copiedCount < tokenCount) {
        int64_t topkPos = logicalSparseOffset + copiedCount;
        int64_t selBlockTableIdx = topkPos / selectionKvBlockSize_;
        int64_t selBlockOffset = topkPos % selectionKvBlockSize_;
        int64_t writeCount = tokenCount - copiedCount;
        int64_t remainingInBlock = selectionKvBlockSize_ - selBlockOffset;
        if (writeCount > remainingInBlock) {
            writeCount = remainingInBlock;
        }

        int32_t selBlockNum = selectionKvBlockTableGm_.GetValue(
            selectionRow * selectionMaxBlockNum_ + selBlockTableIdx);
        if (selBlockNum >= 0) {
            DataCopyExtParams kvParams;
            kvParams.blockCount = writeCount;
            kvParams.blockLen = constInfo.headDim * sizeof(KV_T);
            kvParams.srcStride = 0;
            kvParams.dstStride = 0;

            int64_t dstKvAddr = static_cast<int64_t>(selBlockNum) * selectionKvBlockSize_ *
                                    static_cast<int64_t>(constInfo.headDim) +
                                selBlockOffset * static_cast<int64_t>(constInfo.headDim);
            LocalTensor<KV_T> srcKv =
                kvMergUb_[mergeMte3Idx % 2 * 32 * 512 + copiedCount * static_cast<int64_t>(constInfo.headDim)];
            DataCopyPad(selectionKvCacheGm_[dstKvAddr], srcKv, kvParams);

            DataCopyExtParams ropeParams;
            ropeParams.blockCount = writeCount;
            ropeParams.blockLen = constInfo.headDimRope * sizeof(KV_T);
            ropeParams.srcStride = 0;
            ropeParams.dstStride = 0;

            int64_t dstRopeAddr = static_cast<int64_t>(selBlockNum) * selectionKvBlockSize_ *
                                      static_cast<int64_t>(constInfo.headDimRope) +
                                  selBlockOffset * static_cast<int64_t>(constInfo.headDimRope);
            LocalTensor<KV_T> srcRope =
                ropeMergUb_[mergeMte3Idx % 2 * 32 * 64 + copiedCount * static_cast<int64_t>(constInfo.headDimRope)];
            DataCopyPad(selectionKRopeGm_[dstRopeAddr], srcRope, ropeParams);
        }

        int64_t statusAddr = selectionRow * (static_cast<int64_t>(constInfo.sparseBlockCount) + 1) + topkPos;
        for (int64_t idx = 0; idx < writeCount; idx++) {
            int32_t topkValue = topkGm_.GetValue(runInfo.topKBaseOffset + topkPos + idx);
            selectionKvBlockStatusGm_.SetValue(statusAddr + idx, topkValue);
        }
        copiedCount += writeCount;
    }

    if (logicalSparseOffset == 0 && GetSubBlockIdx() == 0) {
        int32_t actualSeq = static_cast<int32_t>(constInfo.sparseBlockCount);
        selectionKvActualSeqGm_.SetValue(selectionRow, actualSeq);
        selectionKvBlockStatusGm_.SetValue(
            selectionRow * (static_cast<int64_t>(constInfo.sparseBlockCount) + 1) +
            static_cast<int64_t>(constInfo.sparseBlockCount),
            actualSeq);
    }
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline bool FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::IsSelectionUpdateEnabled() const
{
    return enableSelectionUpdate_;
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline bool FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::UseAllCoreSelectionUpdate() const
{
    return useAllCoreSelectionUpdate_;
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline bool FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::UsePipelineSelectionUpdate() const
{
    return enableSelectionUpdate_ && useAllCoreSelectionUpdate_ && constInfo.sparseBlockCount <= 1024 &&
        selectionTopkBlockSize_ == 1 && constInfo.sparseBlockSize == 1;
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline uint64_t FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::GetActualQSeqLenForSelectionUpdate(uint32_t batchIdx)
{
    if constexpr (LAYOUT_T == FusedSparseAttentionOverlapLayout::TND) {
        if (batchIdx > 0) {
            return actualSeqLengthsQGm.GetValue(batchIdx) - actualSeqLengthsQGm.GetValue(batchIdx - 1);
        }
        return actualSeqLengthsQGm.GetValue(0);
    } else {
        if (constInfo.actualLenDimsQ == 0) {
            return constInfo.qSeqSize;
        }
        if (constInfo.actualLenDimsQ == 1) {
            return actualSeqLengthsQGm.GetValue(0);
        }
        return actualSeqLengthsQGm.GetValue(batchIdx);
    }
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline uint64_t FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::GetActualKVSeqLenForSelectionUpdate(uint32_t batchIdx)
{
    if constexpr (KV_LAYOUT_T == FusedSparseAttentionOverlapLayout::TND) {
        if (batchIdx > 0) {
            return actualSeqLengthsKVGm.GetValue(batchIdx) - actualSeqLengthsKVGm.GetValue(batchIdx - 1);
        }
        return actualSeqLengthsKVGm.GetValue(0);
    } else {
        if (constInfo.actualLenDimsKV == 0) {
            return constInfo.kvSeqSize;
        }
        if (constInfo.actualLenDimsKV == 1) {
            return actualSeqLengthsKVGm.GetValue(0);
        }
        return actualSeqLengthsKVGm.GetValue(batchIdx);
    }
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::CopySelectionUpdateTokenFromFullCache(
    int64_t selectionRow, uint32_t batchIdx, int64_t topkPos, int32_t topkValue, int64_t s2IdLimit)
{
    if constexpr (!PAGE_ATTENTION) {
        return;
    }
    if (topkValue < 0 || static_cast<int64_t>(topkValue) >= s2IdLimit) {
        return;
    }

    int64_t selBlockTableIdx = topkPos / selectionKvBlockSize_;
    int32_t selBlockNum = selectionKvBlockTableGm_.GetValue(
        selectionRow * selectionMaxBlockNum_ + selBlockTableIdx);
    if (selBlockNum < 0) {
        return;
    }

    int64_t fullBlockTableIdx = static_cast<int64_t>(topkValue) / constInfo.kvCacheBlockSize;
    int32_t fullBlockNum = blkTableGm_.GetValue(
        static_cast<int64_t>(batchIdx) * constInfo.maxBlockNumPerBatch + fullBlockTableIdx);
    if (fullBlockNum < 0) {
        return;
    }

    int64_t selBlockOffset = topkPos % selectionKvBlockSize_;
    int64_t fullBlockOffset = static_cast<int64_t>(topkValue) % constInfo.kvCacheBlockSize;
    int64_t srcTokenOffset = static_cast<int64_t>(fullBlockNum) * constInfo.kvCacheBlockSize *
                                 static_cast<int64_t>(constInfo.kvHeadNum) +
                             fullBlockOffset;
    int64_t dstKvAddr = static_cast<int64_t>(selBlockNum) * selectionKvBlockSize_ *
                            static_cast<int64_t>(constInfo.headDim) +
                        selBlockOffset * static_cast<int64_t>(constInfo.headDim);

    DataCopyExtParams kvParams;
    kvParams.blockCount = 1;
    kvParams.blockLen = constInfo.headDim * sizeof(KV_T);
    kvParams.srcStride = 0;
    kvParams.dstStride = 0;
    DataCopyPadExtParams<KV_T> padParams;
    DataCopyPad(kvMergUb_, keyGm_[srcTokenOffset * static_cast<int64_t>(constInfo.headDim)], kvParams, padParams);

    if (constInfo.headDimRope == 0) {
        SetFlag<AscendC::HardEvent::MTE2_MTE3>(0);
        WaitFlag<AscendC::HardEvent::MTE2_MTE3>(0);
        DataCopyPad(selectionKvCacheGm_[dstKvAddr], kvMergUb_, kvParams);
        SetFlag<AscendC::HardEvent::MTE3_MTE2>(0);
        WaitFlag<AscendC::HardEvent::MTE3_MTE2>(0);
        return;
    }
    int64_t dstRopeAddr = static_cast<int64_t>(selBlockNum) * selectionKvBlockSize_ *
                               static_cast<int64_t>(constInfo.headDimRope) +
                           selBlockOffset * static_cast<int64_t>(constInfo.headDimRope);
    DataCopyExtParams ropeParams;
    ropeParams.blockCount = 1;
    ropeParams.blockLen = constInfo.headDimRope * sizeof(KV_T);
    ropeParams.srcStride = 0;
    ropeParams.dstStride = 0;
    DataCopyPad(ropeMergUb_, keyRopeGm_[srcTokenOffset * static_cast<int64_t>(constInfo.headDimRope)],
        ropeParams, padParams);
    SetFlag<AscendC::HardEvent::MTE2_MTE3>(0);
    WaitFlag<AscendC::HardEvent::MTE2_MTE3>(0);

    DataCopyPad(selectionKvCacheGm_[dstKvAddr], kvMergUb_, kvParams);
    DataCopyPad(selectionKRopeGm_[dstRopeAddr], ropeMergUb_, ropeParams);
    SetFlag<AscendC::HardEvent::MTE3_MTE2>(0);
    WaitFlag<AscendC::HardEvent::MTE3_MTE2>(0);
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::UpdateSelectionRange(
    int64_t selectionRow, uint32_t batchIdx, int64_t tokenStart, int64_t tokenEnd, int64_t s2IdLimit,
    bool appendActualSeq)
{
    int64_t topkBase = selectionRow * static_cast<int64_t>(constInfo.sparseBlockCount);
    int64_t statusBase = selectionRow * (static_cast<int64_t>(constInfo.sparseBlockCount) + 1);
    constexpr int64_t statusElementsPerDataBlock = BYTE_BLOCK / sizeof(int32_t);
    int64_t tokenCount = tokenEnd - tokenStart;
    int64_t statusStart = statusBase + tokenStart;
    LocalTensor<int32_t> statusLocal = v0ValidSizeUb_;
    int64_t statusLocalOffset = 0;
    int64_t statusCopyStart = statusStart;
    int64_t statusCopyCount = tokenCount + static_cast<int64_t>(appendActualSeq);
    bool useAlignedCopy = statusStart % statusElementsPerDataBlock == 0;
    if (!useAlignedCopy) {
        statusCopyStart = statusStart / statusElementsPerDataBlock * statusElementsPerDataBlock;
        statusLocalOffset = statusStart - statusCopyStart;
        statusCopyCount = statusElementsPerDataBlock;
        DataCopyExtParams loadStatusParams;
        loadStatusParams.blockCount = 1;
        loadStatusParams.blockLen = BYTE_BLOCK;
        loadStatusParams.srcStride = 0;
        loadStatusParams.dstStride = 0;
        DataCopyPadExtParams<int32_t> padParams{false, 0, 0, 0};
        DataCopyPad(statusLocal, selectionKvBlockStatusGm_[statusCopyStart], loadStatusParams, padParams);
        SetFlag<AscendC::HardEvent::MTE2_S>(1);
        WaitFlag<AscendC::HardEvent::MTE2_S>(1);
    }
    for (int64_t topkPos = tokenStart; topkPos < tokenEnd; topkPos++) {
        int32_t topkValue = topkGm_.GetValue(topkBase + topkPos);
        int64_t localStatusIdx = statusLocalOffset + topkPos - tokenStart;
        int32_t currentStatus = useAlignedCopy ?
            selectionKvBlockStatusGm_.GetValue(statusBase + topkPos) : statusLocal.GetValue(localStatusIdx);
        if (currentStatus != topkValue) {
            CopySelectionUpdateTokenFromFullCache(selectionRow, batchIdx, topkPos, topkValue, s2IdLimit);
        }
        statusLocal.SetValue(localStatusIdx, topkValue);
    }
    if (appendActualSeq) {
        statusLocal.SetValue(statusLocalOffset + tokenCount, static_cast<int32_t>(constInfo.sparseBlockCount));
    }
    if (statusCopyCount > 0) {
        SetFlag<AscendC::HardEvent::S_MTE3>(1);
        WaitFlag<AscendC::HardEvent::S_MTE3>(1);
        DataCopyExtParams statusParams;
        statusParams.blockCount = 1;
        statusParams.blockLen = static_cast<uint32_t>(statusCopyCount * sizeof(int32_t));
        statusParams.srcStride = 0;
        statusParams.dstStride = 0;
        DataCopyPad(selectionKvBlockStatusGm_[statusCopyStart], statusLocal, statusParams);
        SetFlag<AscendC::HardEvent::MTE3_S>(1);
        WaitFlag<AscendC::HardEvent::MTE3_S>(1);
    }
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::RefreshSelectionStatusRange(
    int64_t topkBase, int64_t statusBase, int64_t tokenStart, int64_t tokenEnd)
{
    for (int64_t topkPos = tokenStart; topkPos < tokenEnd; topkPos++) {
        selectionKvBlockStatusGm_.SetValue(
            statusBase + topkPos, topkGm_.GetValue(topkBase + topkPos));
    }
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::RunAllCoreSelectionUpdate()
{
    if (!enableSelectionUpdate_ || !useAllCoreSelectionUpdate_ || selectionKvBlockSize_ <= 0 ||
        selectionMaxBlockNum_ <= 0 || selectionTopkBlockSize_ != 1 || constInfo.sparseBlockSize != 1) {
        return;
    }

    uint32_t aivCoreIdx = GetBlockIdx();
    uint32_t aivCoreNum = GetBlockNum();
    uint32_t updateStartCore = (aivCoreNum > 2) ? 2 : 0;
    if (!UsePipelineSelectionUpdate() && aivCoreNum > 4) {
        updateStartCore = 4;
    }
    if (aivCoreIdx < updateStartCore) {
        return;
    }
    uint32_t updateCoreIdx = aivCoreIdx - updateStartCore;
    uint32_t updateCoreNum = aivCoreNum - updateStartCore;
    if (updateCoreIdx >= updateCoreNum) {
        return;
    }
    if (updateCoreNum == 0) {
        return;
    }

    int64_t qTokenPrefix = 0;
    for (uint32_t batchIdx = 0; batchIdx < constInfo.batchSize; batchIdx++) {
        uint64_t actualQSeqLen = GetActualQSeqLenForSelectionUpdate(batchIdx);
        uint64_t actualKVSeqLen = GetActualKVSeqLenForSelectionUpdate(batchIdx);
        for (uint64_t qIdx = 0; qIdx < actualQSeqLen; qIdx++) {
            int64_t s2IdLimit = static_cast<int64_t>(actualKVSeqLen);
            if (constInfo.sparseMode == 3) {
                s2IdLimit = static_cast<int64_t>(actualKVSeqLen) - static_cast<int64_t>(actualQSeqLen) +
                            static_cast<int64_t>(qIdx) + 1;
            }
            if (s2IdLimit < 0) {
                s2IdLimit = 0;
            }
            for (uint32_t n2Idx = 0; n2Idx < constInfo.kvHeadNum; n2Idx++) {
                int64_t selectionRow =
                    (qTokenPrefix + static_cast<int64_t>(qIdx)) * static_cast<int64_t>(constInfo.kvHeadNum) +
                    static_cast<int64_t>(n2Idx);
                int64_t statusBase = selectionRow * (static_cast<int64_t>(constInfo.sparseBlockCount) + 1);
                constexpr int64_t statusElementsPerDataBlock = BYTE_BLOCK / sizeof(int32_t);
                int64_t statusMisalignment = statusBase % statusElementsPerDataBlock;
                int64_t prefixCount =
                    statusMisalignment == 0 ? 0 : statusElementsPerDataBlock - statusMisalignment;
                if (prefixCount > static_cast<int64_t>(constInfo.sparseBlockCount)) {
                    prefixCount = static_cast<int64_t>(constInfo.sparseBlockCount);
                }
                int64_t middleTokenCount = static_cast<int64_t>(constInfo.sparseBlockCount) - prefixCount;
                middleTokenCount = middleTokenCount / statusElementsPerDataBlock * statusElementsPerDataBlock;
                int64_t middleBlockCount = middleTokenCount / statusElementsPerDataBlock;
                int64_t middleBlocksPerCore =
                    CeilDiv(middleBlockCount, static_cast<int64_t>(updateCoreNum));
                int64_t middleBlockStart = static_cast<int64_t>(updateCoreIdx) * middleBlocksPerCore;
                int64_t middleBlockEnd = middleBlockStart + middleBlocksPerCore;
                if (middleBlockEnd > middleBlockCount) {
                    middleBlockEnd = middleBlockCount;
                }

                if (updateCoreIdx == 0 && prefixCount > 0) {
                    UpdateSelectionRange(selectionRow, batchIdx, 0, prefixCount, s2IdLimit);
                }
                int64_t middleTokenStart = prefixCount + middleBlockStart * statusElementsPerDataBlock;
                int64_t middleTokenEnd = prefixCount + middleBlockEnd * statusElementsPerDataBlock;
                if (middleTokenStart < middleTokenEnd) {
                    UpdateSelectionRange(
                        selectionRow, batchIdx, middleTokenStart, middleTokenEnd, s2IdLimit);
                }
                if (updateCoreIdx == 0) {
                    int64_t suffixStart = prefixCount + middleTokenCount;
                    UpdateSelectionRange(selectionRow, batchIdx, suffixStart,
                        static_cast<int64_t>(constInfo.sparseBlockCount), s2IdLimit, true);
                    int32_t actualSeq = static_cast<int32_t>(constInfo.sparseBlockCount);
                    selectionKvActualSeqGm_.SetValue(selectionRow, actualSeq);
                }
            }
        }
        qTokenPrefix += static_cast<int64_t>(actualQSeqLen);
    }
    pipe_barrier(PIPE_ALL);
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::CopyOutSelectionUpdateFromKvMerge(const RunInfo &runInfo)
{
    if (!enableSelectionUpdate_ || selectionKvBlockSize_ <= 0 || selectionMaxBlockNum_ <= 0 ||
        selectionTopkBlockSize_ != 1 || constInfo.sparseBlockSize != 1) {
        return;
    }
    if (useAllCoreSelectionUpdate_ && constInfo.sparseBlockCount > 1024) {
        return;
    }

    int64_t qTokenOffset = 0;
    if constexpr (LAYOUT_T == FusedSparseAttentionOverlapLayout::TND) {
        uint64_t actualSeqQPrefixSum =
            (runInfo.bIdx <= 0) ? 0 : actualSeqLengthsQGm.GetValue(runInfo.bIdx - 1);
        qTokenOffset = static_cast<int64_t>(actualSeqQPrefixSum) +
                       static_cast<int64_t>(runInfo.gS1Idx / constInfo.gSize);
    } else {
        qTokenOffset = static_cast<int64_t>(runInfo.bIdx) * static_cast<int64_t>(constInfo.qSeqSize) +
                       static_cast<int64_t>(runInfo.gS1Idx / constInfo.gSize);
    }
    int64_t selectionRow =
        qTokenOffset * static_cast<int64_t>(constInfo.kvHeadNum) + static_cast<int64_t>(runInfo.n2Idx);

    int64_t s2ProcessSize = runInfo.actualSingleProcessSInnerSize;
    int64_t s2Pair = CeilDiv(s2ProcessSize, 2L * constInfo.sparseBlockSize);
    int64_t s2GmStartOffset = GetSubBlockIdx() == 0 ? 0 :
        CeilDiv(s2Pair, 2L) * 2 * constInfo.sparseBlockSize;
    int64_t s2GmLimit = GetSubBlockIdx() == 0 ?
        CeilDiv(s2Pair, 2L) * 2 * constInfo.sparseBlockSize : s2ProcessSize;
    if (s2GmLimit > s2ProcessSize) {
        s2GmLimit = s2ProcessSize;
    }

    int64_t localOffset = s2GmStartOffset;
    while (localOffset < s2GmLimit) {
        int64_t topkPos = static_cast<int64_t>(runInfo.s2Idx) * static_cast<int64_t>(constInfo.s2BaseSize) +
                          localOffset;
        int64_t selBlockTableIdx = topkPos / selectionKvBlockSize_;
        int64_t selBlockOffset = topkPos % selectionKvBlockSize_;
        int64_t writeCount = s2GmLimit - localOffset;
        if (writeCount > 32) {
            writeCount = 32;
        }
        int64_t remainingInBlock = selectionKvBlockSize_ - selBlockOffset;
        if (writeCount > remainingInBlock) {
            writeCount = remainingInBlock;
        }

        int64_t statusAddr = selectionRow * (static_cast<int64_t>(constInfo.sparseBlockCount) + 1) + topkPos;
        int64_t missDstIdx[32];
        int64_t missSrcIdx[32];
        int64_t missCount = 0;
        bool statusDirty = false;
        int64_t s2IdLimit = runInfo.curActualSeqLenOri;
        if (constInfo.sparseMode == 3) {
            s2IdLimit = runInfo.curActualSeqLenOri - runInfo.actS1Size +
                        runInfo.gS1Idx / constInfo.gSize + 1;
        }
        int64_t statusBase = selectionRow * (static_cast<int64_t>(constInfo.sparseBlockCount) + 1);
        for (int64_t idx = 0; idx < writeCount; idx++) {
            int32_t topkValue = topkGm_.GetValue(runInfo.topKBaseOffset + topkPos + idx);
            int32_t currentStatus = selectionKvBlockStatusGm_.GetValue(statusAddr + idx);
            if (currentStatus == topkValue) {
                continue;
            }
            statusDirty = true;
            if (topkValue < 0) {
                continue;
            }
            int64_t srcIdx = idx;
            int64_t absoluteOffset = localOffset + idx;
            int64_t pairSize = 2L * static_cast<int64_t>(constInfo.sparseBlockSize);
            int64_t pairOffset = (absoluteOffset / pairSize) * pairSize;
            if (constInfo.sparseBlockSize == 1 && pairOffset + 1 < s2ProcessSize) {
                int64_t realS2Idx0 = -1;
                int64_t realS2Idx1 = -1;
                GetRealS2Idx(pairOffset, realS2Idx0, runInfo.topKBaseOffset, runInfo);
                GetRealS2Idx(pairOffset + 1, realS2Idx1, runInfo.topKBaseOffset, runInfo);
                int64_t keyOffset0 = GetKeyGmOffset(realS2Idx0, runInfo, s2IdLimit);
                int64_t keyOffset1 = GetKeyGmOffset(realS2Idx1, runInfo, s2IdLimit);
                if (keyOffset0 >= 0 && keyOffset1 >= 0 && keyOffset1 < keyOffset0) {
                    int64_t srcAbsoluteOffset = (absoluteOffset == pairOffset) ? pairOffset + 1 : pairOffset;
                    if (srcAbsoluteOffset >= localOffset && srcAbsoluteOffset < localOffset + writeCount) {
                        srcIdx = srcAbsoluteOffset - localOffset;
                    }
                }
            }
            missDstIdx[missCount] = idx;
            missSrcIdx[missCount] = srcIdx;
            missCount++;
        }

        int32_t selBlockNum = -1;
        if (missCount > 0) {
            selBlockNum = selectionKvBlockTableGm_.GetValue(
                selectionRow * selectionMaxBlockNum_ + selBlockTableIdx);
        }
        if (selBlockNum >= 0 && missCount > 0) {
            DataCopyExtParams kvParams;
            kvParams.blockLen = constInfo.headDim * sizeof(KV_T);
            kvParams.srcStride = 0;
            kvParams.dstStride = 0;
            DataCopyPadExtParams<KV_T> padParams;

            DataCopyExtParams ropeParams;
            ropeParams.blockLen = constInfo.headDimRope * sizeof(KV_T);
            ropeParams.srcStride = 0;
            ropeParams.dstStride = 0;

            kvParams.blockCount = writeCount;
            DataCopyPad(kvMergUb_,
                kvMergeGm_[runInfo.loop % MERGE_CACHE_GM_BUF_NUM * 512 * 576 +
                            localOffset * static_cast<int64_t>(constInfo.headDim)],
                kvParams, padParams);
            ropeParams.blockCount = writeCount;
            DataCopyPad(ropeMergUb_,
                kvMergeGm_[runInfo.loop % MERGE_CACHE_GM_BUF_NUM * 512 * 576 +
                           512 * static_cast<int64_t>(constInfo.headDim) +
                           localOffset * static_cast<int64_t>(constInfo.headDimRope)],
                ropeParams, padParams);
            SetFlag<AscendC::HardEvent::MTE2_MTE3>(0);
            WaitFlag<AscendC::HardEvent::MTE2_MTE3>(0);
            int64_t missIdx = 0;
            while (missIdx < missCount) {
                int64_t dstStart = missDstIdx[missIdx];
                int64_t srcStart = missSrcIdx[missIdx];
                int64_t runLen = 1;
                while (missIdx + runLen < missCount &&
                       missDstIdx[missIdx + runLen] == dstStart + runLen &&
                       missSrcIdx[missIdx + runLen] == srcStart + runLen) {
                    runLen++;
                }
                DataCopyExtParams missKvParams = kvParams;
                missKvParams.blockCount = runLen;
                int64_t dstKvAddr = static_cast<int64_t>(selBlockNum) * selectionKvBlockSize_ *
                                        static_cast<int64_t>(constInfo.headDim) +
                                    (selBlockOffset + dstStart) * static_cast<int64_t>(constInfo.headDim);
                DataCopyPad(selectionKvCacheGm_[dstKvAddr],
                    kvMergUb_[srcStart * static_cast<int64_t>(constInfo.headDim)], missKvParams);
                missIdx += runLen;
            }

            missIdx = 0;
            while (missIdx < missCount) {
                int64_t dstStart = missDstIdx[missIdx];
                int64_t srcStart = missSrcIdx[missIdx];
                int64_t runLen = 1;
                while (missIdx + runLen < missCount &&
                       missDstIdx[missIdx + runLen] == dstStart + runLen &&
                       missSrcIdx[missIdx + runLen] == srcStart + runLen) {
                    runLen++;
                }
                DataCopyExtParams missRopeParams = ropeParams;
                missRopeParams.blockCount = runLen;
                int64_t dstRopeAddr = static_cast<int64_t>(selBlockNum) * selectionKvBlockSize_ *
                                          static_cast<int64_t>(constInfo.headDimRope) +
                                      (selBlockOffset + dstStart) *
                                          static_cast<int64_t>(constInfo.headDimRope);
                DataCopyPad(selectionKRopeGm_[dstRopeAddr],
                    ropeMergUb_[srcStart * static_cast<int64_t>(constInfo.headDimRope)], missRopeParams);
                missIdx += runLen;
            }
            SetFlag<AscendC::HardEvent::MTE3_MTE2>(0);
            WaitFlag<AscendC::HardEvent::MTE3_MTE2>(0);
        }
        if (statusDirty) {
            RefreshSelectionStatusRange(runInfo.topKBaseOffset, statusBase, topkPos, topkPos + writeCount);
        }
        localOffset += writeCount;
    }

    if (runInfo.s2Idx == 0 && GetSubBlockIdx() == 0) {
        int32_t actualSeq = static_cast<int32_t>(constInfo.sparseBlockCount);
        selectionKvActualSeqGm_.SetValue(selectionRow, actualSeq);
        selectionKvBlockStatusGm_.SetValue(
            selectionRow * (static_cast<int64_t>(constInfo.sparseBlockCount) + 1) +
            static_cast<int64_t>(constInfo.sparseBlockCount),
            actualSeq);
    }
}

// b s1 k
template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::MergeKv(const RunInfo &runInfo)
{
    int64_t s2ProcessSize = runInfo.actualSingleProcessSInnerSize;
    int64_t s2Pair = CeilDiv(s2ProcessSize, 2L * constInfo.sparseBlockSize);
    int64_t topkGmBaseOffset = 0;

    if constexpr (LAYOUT_T == FusedSparseAttentionOverlapLayout::TND) {
        uint64_t actualSeqQPrefixSum = (runInfo.bIdx <= 0) ? 0 : actualSeqLengthsQGm.GetValue(runInfo.bIdx - 1);
        topkGmBaseOffset += (actualSeqQPrefixSum + runInfo.gS1Idx / constInfo.gSize) * constInfo.kvHeadNum *
                            constInfo.sparseBlockCount + runInfo.n2Idx * constInfo.sparseBlockCount;
    } else {
        topkGmBaseOffset += runInfo.bIdx * constInfo.qSeqSize * constInfo.sparseBlockCount +
                            runInfo.gS1Idx / constInfo.gSize * constInfo.sparseBlockCount;
    }
    int64_t mergeMte3Idx = 0;
    int64_t mte2Size = 0;
    int64_t mte3Size = 0;
    int64_t s2IdxArray0 = -1;
    int64_t s2IdxArray1 = -1;
    bool needWaitMte3ToMte2 = true;
    SetFlag<AscendC::HardEvent::MTE3_MTE2>(0);
    SetFlag<AscendC::HardEvent::MTE3_MTE2>(1);
    int64_t s2GmStartOffset = GetSubBlockIdx() == 0 ? 0 : CeilDiv(s2Pair, 2L) * 2 * constInfo.sparseBlockSize;
    int64_t s2GmLimit = GetSubBlockIdx() == 0 ? CeilDiv(s2Pair, 2L) * 2 * constInfo.sparseBlockSize: s2ProcessSize;
    if (s2GmLimit > s2ProcessSize) {
        s2GmLimit = s2ProcessSize;
    }
    for (int64_t s2GmOffsetArray = s2GmStartOffset; s2GmOffsetArray < s2GmLimit; s2GmOffsetArray += 2 * constInfo.sparseBlockSize) {
        if (needWaitMte3ToMte2) {
            WaitFlag<AscendC::HardEvent::MTE3_MTE2>(mergeMte3Idx % 2);
            needWaitMte3ToMte2 = false;
        }
        GetRealS2Idx(s2GmOffsetArray, s2IdxArray0, topkGmBaseOffset, runInfo);
        if (unlikely(s2IdxArray0 < 0)) {
            CopyOutMrgeResult(mte2Size, mte3Size, s2GmStartOffset, mergeMte3Idx, runInfo);
            SetFlag<AscendC::HardEvent::MTE3_MTE2>(mergeMte3Idx % 2);
            mergeMte3Idx++;
            break;
        }
        GetRealS2Idx(s2GmOffsetArray + constInfo.sparseBlockSize, s2IdxArray1, topkGmBaseOffset, runInfo);
        CopyInKv(mte2Size, mte3Size, mergeMte3Idx, s2IdxArray0, s2IdxArray1, runInfo);
        if ((mte2Size - mte3Size + 2 * constInfo.sparseBlockSize > 32) ||
            s2GmOffsetArray + 2 * constInfo.sparseBlockSize >= s2GmLimit) {
            CopyOutMrgeResult(mte2Size, mte3Size, s2GmStartOffset, mergeMte3Idx, runInfo);
            mte3Size = mte2Size;
            SetFlag<AscendC::HardEvent::MTE3_MTE2>(mergeMte3Idx % 2);
            mergeMte3Idx++;
            needWaitMte3ToMte2 = true;
        }
    }

    if (unlikely(s2GmStartOffset + mte2Size < s2GmLimit)) {
        SetFlag<AscendC::HardEvent::MTE3_V>(0);
        WaitFlag<AscendC::HardEvent::MTE3_V>(0);
        WaitFlag<AscendC::HardEvent::MTE3_MTE2>(mergeMte3Idx & 1);
        Duplicate(kvMergUb_, static_cast<KV_T>(0.0), constInfo.headDim);
        SetFlag<AscendC::HardEvent::V_MTE3>(0);
        WaitFlag<AscendC::HardEvent::V_MTE3>(0);

        DataCopyExtParams dataCopyParams;
        dataCopyParams.blockCount = 1;
        dataCopyParams.blockLen = constInfo.headDim * sizeof(KV_T);
        dataCopyParams.srcStride = 0;
        dataCopyParams.dstStride = 0;
        for (int64_t s2GmOffset = s2GmStartOffset + mte2Size; s2GmOffset < s2GmLimit; s2GmOffset++) {
            DataCopyPad(kvMergeGm_[runInfo.loop % MERGE_CACHE_GM_BUF_NUM * 512 * 576 + s2GmOffset * constInfo.headDim],
                        kvMergUb_, dataCopyParams);
        }
        dataCopyParams.blockLen = constInfo.headDimRope * sizeof(KV_T);
        for (int64_t s2GmOffset = s2GmStartOffset + mte2Size; s2GmOffset < s2GmLimit; s2GmOffset++) {
            DataCopyPad(kvMergeGm_[runInfo.loop % MERGE_CACHE_GM_BUF_NUM * 512 * 576 + 512 * constInfo.headDim +
                                   s2GmOffset * constInfo.headDimRope],
                        kvMergUb_, dataCopyParams);
        }
        SetFlag<AscendC::HardEvent::MTE3_MTE2>(mergeMte3Idx & 1);
        mergeMte3Idx++;
    }
    WaitFlag<AscendC::HardEvent::MTE3_MTE2>(0);
    WaitFlag<AscendC::HardEvent::MTE3_MTE2>(1);
    v0ValidSizeUb_.SetValue(runInfo.loop % MERGE_CACHE_GM_BUF_NUM, mte2Size);
    SetFlag<AscendC::HardEvent::S_MTE3>(1);
    WaitFlag<AscendC::HardEvent::S_MTE3>(1);
    DataCopyExtParams dataCopyParams;
    dataCopyParams.blockCount = 1;
    dataCopyParams.blockLen = 128 * sizeof(int32_t);
    dataCopyParams.srcStride = 0;
    dataCopyParams.dstStride = 0;
    DataCopyPad(kvValidSizeGm_[runInfo.loop % MERGE_CACHE_GM_BUF_NUM * (128 * 2) + GetSubBlockIdx() * 128],
                v0ValidSizeUb_, dataCopyParams);
    return;
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::ProcessVec1L(const RunInfo &info)
{
    uint32_t nBufferLoopTimes = (info.actMBaseSize + constInfo.nBufferMBaseSize - 1) / constInfo.nBufferMBaseSize;
    uint32_t nBufferTail = info.actMBaseSize - (nBufferLoopTimes - 1) * constInfo.nBufferMBaseSize;
    for (uint32_t i = 0; i < nBufferLoopTimes; i++) {
        MSplitInfo mSplitInfo;
        mSplitInfo.nBufferIdx = i;
        mSplitInfo.nBufferStartM = i * constInfo.nBufferMBaseSize;
        mSplitInfo.nBufferDealM = (i + 1 != nBufferLoopTimes) ? constInfo.nBufferMBaseSize : nBufferTail;

        mSplitInfo.vecDealM = (mSplitInfo.nBufferDealM <= 16) ? mSplitInfo.nBufferDealM :
                                                                (((mSplitInfo.nBufferDealM + 15) / 16 + 1) / 2 * 16);
        mSplitInfo.vecStartM = 0;
        if (GetBlockIdx() % 2 == 1) {
            mSplitInfo.vecStartM = mSplitInfo.vecDealM;
            mSplitInfo.vecDealM = mSplitInfo.nBufferDealM - mSplitInfo.vecDealM;
        }

        CrossCoreWaitFlag(constInfo.syncC1V1);
        // vec1 compute
        ProcessVec1SingleBuf(info, mSplitInfo);
        CrossCoreSetFlag<ConstInfo::FUSED_SPARSE_ATTENTION_OVERLAP_SYNC_MODE2, PIPE_MTE3>(constInfo.syncV1C2);
        CrossCoreWaitFlag(constInfo.syncC2V1);
        // add nUpdate to mm2ResGm
        if (info.actualSingleProcessSInnerSize != 0) {
            ProcessAmlaNupdate(info, mSplitInfo);
            CrossCoreSetFlag<ConstInfo::FUSED_SPARSE_ATTENTION_OVERLAP_SYNC_MODE2, PIPE_MTE3>(constInfo.syncV1NupdateC2);
        }
        // move lse for flash decode
        if (info.s2Idx == info.curSInnerLoopTimes - 1) {
            if (info.tndIsS2SplitCore) {
                if constexpr (FLASH_DECODE) {
                    uint32_t outIdx = info.loop % (constInfo.preLoadNum);
                    auto sumTensor = softmaxSumUb[outIdx * SOFTMAX_TMP_BUFFER_OFFSET / sizeof(T)];
                    auto maxTensor = softmaxMaxUb[outIdx * SOFTMAX_TMP_BUFFER_OFFSET / sizeof(T)];
                    ComputeLogSumExpAndCopyToGm(info, mSplitInfo, sumTensor, maxTensor);
                }
            }
        }
    }
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline uint64_t FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::CalcAccumOffset(uint32_t bN2Idx, uint32_t gS1Idx)
{
    return 0;
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::ProcessVec2SingleBuf(const RunInfo &info,
                                                                                  const MSplitInfo &mSplitInfo)
{
    if (info.s2Idx + 1 != info.curSInnerLoopTimes) {
        return;
    }
    if (mSplitInfo.vecDealM == 0) {
        return;
    }

    ProcessVec2Inner(info, mSplitInfo, 0, mSplitInfo.vecDealM);
}

template <typename FusedSparseAttentionOverlapTraits> __aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::ProcessVec2L(const RunInfo &info)
{
    uint32_t nBufferLoopTimes = (info.actMBaseSize + constInfo.nBufferMBaseSize - 1) / constInfo.nBufferMBaseSize;
    uint32_t nBufferTail = info.actMBaseSize - (nBufferLoopTimes - 1) * constInfo.nBufferMBaseSize;
    for (uint32_t i = 0; i < nBufferLoopTimes; i++) {
        MSplitInfo mSplitInfo;
        mSplitInfo.nBufferIdx = i;
        mSplitInfo.nBufferStartM = i * constInfo.nBufferMBaseSize;
        mSplitInfo.nBufferDealM = (i + 1 != nBufferLoopTimes) ? constInfo.nBufferMBaseSize : nBufferTail;

        mSplitInfo.vecDealM = (mSplitInfo.nBufferDealM <= 16) ? mSplitInfo.nBufferDealM :
                                                                (((mSplitInfo.nBufferDealM + 15) / 16 + 1) / 2 * 16);
        mSplitInfo.vecStartM = 0;
        if (GetBlockIdx() % 2 == 1) {
            mSplitInfo.vecStartM = mSplitInfo.vecDealM;
            mSplitInfo.vecDealM = mSplitInfo.nBufferDealM - mSplitInfo.vecDealM;
        }
        CrossCoreWaitFlag(constInfo.syncC2V2);
        ProcessVec2SingleBuf(info, mSplitInfo);
    }
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::ProcessVec2Inner(const RunInfo &info,
                                                                              const MSplitInfo &mSplitInfo,
                                                                              uint32_t mStartRow, uint32_t mDealSize)
{
    uint32_t mSplitSize = BASE_BLOCK_MAX_ELEMENT_NUM / constInfo.headDim;
    if (mSplitSize > mDealSize) {
        mSplitSize = mDealSize;
    }

    uint32_t loopCount = (mDealSize + mSplitSize - 1) / mSplitSize;
    uint32_t tailSplitSize = mDealSize - (loopCount - 1) * mSplitSize;
    for (uint32_t i = 0, dealSize = mSplitSize; i < loopCount; i++) {
        if (i == (loopCount - 1)) {
            dealSize = tailSplitSize;
        }
        DealBmm2ResBaseBlock(info, mSplitInfo, i * mSplitSize + mStartRow, dealSize,
                             constInfo.headDim, constInfo.headDim);
        pingpongFlag ^= 1; // pingpong 0 1切换
    }
}


template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::GetConfusionTransposeTiling(
    int64_t numR, int64_t numC, const uint32_t stackBufferSize, const uint32_t typeSize,
    ConfusionTransposeTiling &tiling)
{
    (void)stackBufferSize;
    uint32_t blockSize = ONE_BLK_SIZE / typeSize;
    uint32_t height = numC;
    uint32_t width = numR;
    uint32_t highBlock = height / BLOCK_CUBE;
    uint32_t stride = height * blockSize * typeSize / ONE_BLK_SIZE;
    uint32_t repeat = width / blockSize;

    tiling.param0 = blockSize;
    tiling.param1 = height;
    tiling.param2 = width;
    tiling.param3 = highBlock;
    tiling.param4 = stride;
    tiling.param5 = repeat;
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void
FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::Bmm2FDDataCopyOut(const RunInfo &info, LocalTensor<T> &bmm2ResUb,
                                                        uint32_t wsMStart, uint32_t dealRowCount, uint32_t columnCount,
                                                        uint32_t actualColumnCount)
{
    LocalTensor<T> tmp = outputBuff1.Get<T>();
    WaitFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF1_FLAG);
    DataCopy(tmp, bmm2ResUb, columnCount * dealRowCount);
    SetFlag<AscendC::HardEvent::V_MTE3>(SYNC_OUTPUT_BUF1_FLAG);
    WaitFlag<AscendC::HardEvent::V_MTE3>(SYNC_OUTPUT_BUF1_FLAG);
    uint64_t accumTmpOutNum = CalcAccumOffset(info.bIdx, info.gS1Idx);
    uint64_t offset = accumTmpOutNum * constInfo.kvHeadNum * constInfo.mBaseSize * constInfo.headDim +              // taskoffset
                      info.tndCoreStartKVSplitPos * constInfo.kvHeadNum * constInfo.mBaseSize * constInfo.headDim + // 份数offset
                      wsMStart * actualColumnCount;                                                                 // m轴offset
    GlobalTensor<T> dst = accumOutGm[offset];
    if (info.actualSingleProcessSInnerSize== 0) {
        DataCopyExtParams dataCopyParams;
        dataCopyParams.blockCount = dealRowCount;
        dataCopyParams.blockLen = actualColumnCount * sizeof(T);
        dataCopyParams.srcStride = (columnCount - actualColumnCount) / (BYTE_BLOCK / sizeof(T));
        dataCopyParams.dstStride = 0;
        DataCopyPad(dst, tmp, dataCopyParams);
    } else {
        matmul::InitOutput<T>(dst, dealRowCount * actualColumnCount, ConstInfo::FLOAT_ZERO);
    }
    SetFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF1_FLAG);
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void
FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::Bmm2DataCopyOutTrans(const RunInfo &info, LocalTensor<OUT_T> &attenOutUb,
                                                           uint32_t wsMStart, uint32_t dealRowCount,
                                                           uint32_t columnCount, uint32_t actualColumnCount)
{
    DataCopyExtParams dataCopyParams;
    dataCopyParams.blockCount = dealRowCount;
    dataCopyParams.blockLen = actualColumnCount * sizeof(OUT_T);
    dataCopyParams.srcStride = (columnCount - actualColumnCount) / (BYTE_BLOCK / sizeof(OUT_T));
    dataCopyParams.dstStride = 0;
    DataCopyPad(attentionOutGm[info.attenOutOffset + wsMStart * actualColumnCount], attenOutUb, dataCopyParams);    
    return;
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void
FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::Bmm2CastAndCopyOut(const RunInfo &info, LocalTensor<T> &bmm2ResUb,
                                                         uint32_t wsMStart, uint32_t dealRowCount, uint32_t columnCount,
                                                         uint32_t actualColumnCount)
{
    LocalTensor<OUT_T> tmpBmm2ResCastTensor = outputBuff1.Get<OUT_T>();
    WaitFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF1_FLAG);
    if constexpr (IsSameType<OUT_T, bfloat16_t>::value) { // bf16 采取四舍六入五成双模�?
        Cast(tmpBmm2ResCastTensor, bmm2ResUb, AscendC::RoundMode::CAST_RINT, dealRowCount * columnCount);
    } else {
        Cast(tmpBmm2ResCastTensor, bmm2ResUb, AscendC::RoundMode::CAST_ROUND, dealRowCount * columnCount);
    }

    SetFlag<AscendC::HardEvent::V_MTE3>(SYNC_OUTPUT_BUF1_FLAG);
    WaitFlag<AscendC::HardEvent::V_MTE3>(SYNC_OUTPUT_BUF1_FLAG);
    Bmm2DataCopyOutTrans(info, tmpBmm2ResCastTensor, wsMStart, dealRowCount, columnCount, actualColumnCount);
    SetFlag<AscendC::HardEvent::MTE3_V>(SYNC_OUTPUT_BUF1_FLAG);
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void
FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::Bmm2ResCopyOut(const RunInfo &info, LocalTensor<T> &bmm2ResUb, uint32_t wsMStart,
                                                     uint32_t dealRowCount, uint32_t columnCount,
                                                     uint32_t actualColumnCount)
{
    if constexpr (FLASH_DECODE) {
        if (info.tndIsS2SplitCore) {
            Bmm2FDDataCopyOut(info, bmm2ResUb, wsMStart, dealRowCount, columnCount, actualColumnCount);
        } else {
            Bmm2CastAndCopyOut(info, bmm2ResUb, wsMStart, dealRowCount, columnCount, actualColumnCount);
        }
    } else {
        Bmm2CastAndCopyOut(info, bmm2ResUb, wsMStart, dealRowCount, columnCount, actualColumnCount);
    }
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void
FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::DealBmm2ResBaseBlock(const RunInfo &info, const MSplitInfo &mSplitInfo,
                                                           uint32_t startRow, uint32_t dealRowCount,
                                                           uint32_t columnCount, uint32_t actualColumnCount)
{
    uint32_t vec2ComputeSize = dealRowCount * columnCount;
    uint32_t mStart = mSplitInfo.nBufferStartM + mSplitInfo.vecStartM + startRow;
    uint64_t srcGmOffset = (info.bn2IdxInCurCore % constInfo.preLoadNum) * constInfo.bmm2ResUbSize +
                            mStart * columnCount;
    LocalTensor<MM2_OUT_T> tmpBmm2ResUb = inputBuff1.Get<MM2_OUT_T>();
    tmpBmm2ResUb = tmpBmm2ResUb[pingpongFlag * INPUT1_BUFFER_OFFSET / sizeof(MM2_OUT_T)];
    WaitFlag<AscendC::HardEvent::V_MTE2>(SYNC_INPUT_BUF1_FLAG + pingpongFlag);
    DataCopy(tmpBmm2ResUb, mm2ResGm[srcGmOffset], vec2ComputeSize);

    SetFlag<AscendC::HardEvent::MTE2_V>(SYNC_INPUT_BUF1_FLAG);
    WaitFlag<AscendC::HardEvent::MTE2_V>(SYNC_INPUT_BUF1_FLAG);
    
    // 将绝对值大�?e10的数置为0
    LocalTensor<T> bmm2ResUb = tmpBuff1.Get<T>();
    bmm2ResUb.SetSize(vec2ComputeSize);
    LocalTensor<T> absBmm2ResUb = bmm2ResUb.template ReinterpretCast<T>();
    Abs(absBmm2ResUb, tmpBmm2ResUb, vec2ComputeSize);
    pipe_barrier(PIPE_V);
    LocalTensor<uint8_t> cmpMaskUb = absBmm2ResUb.template ReinterpretCast<uint8_t>();
    CompareScalar(cmpMaskUb, absBmm2ResUb, (T)1e10, CMPMODE::LE, vec2ComputeSize);
    pipe_barrier(PIPE_V);
    Select(tmpBmm2ResUb, cmpMaskUb, tmpBmm2ResUb, ConstInfo::FLOAT_ZERO,
           SELMODE::VSEL_TENSOR_SCALAR_MODE, vec2ComputeSize);
    pipe_barrier(PIPE_V);
    uint32_t baseOffset = mSplitInfo.nBufferStartM / 2 + startRow;
    uint32_t idx = info.loop % (constInfo.preLoadNum);
    LocalTensor<T> tmpSumUb = v0ValidSizeBuff.Get<T>()[384]; // sumUb用临时内�?16 * 32B  = 512B
    Brcb(tmpSumUb, aMlaSumUb[idx * SOFTMAX_TMP_BUFFER_OFFSET / sizeof(T) + baseOffset], (dealRowCount + 7) / 8, {1, 8});
    pipe_barrier(PIPE_V);
    RowDivs(bmm2ResUb, tmpBmm2ResUb, tmpSumUb, dealRowCount, columnCount, actualColumnCount);
    pipe_barrier(PIPE_V);
    SetFlag<AscendC::HardEvent::V_MTE2>(SYNC_INPUT_BUF1_FLAG + pingpongFlag);
    Bmm2ResCopyOut(info, bmm2ResUb, mStart, dealRowCount, columnCount, actualColumnCount);
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void
FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::RowDivs(LocalTensor<float> dstUb, LocalTensor<float> src0Ub, LocalTensor<float> src1Ub,
                                uint32_t dealRowCount, uint32_t columnCount, uint32_t actualColumnCount)
{
    // divs by row, 每行的元素除以相同的元素
    // dstUb[i, (j * 8) : (j * 8 + 7)] = src0Ub[i, (j * 8) : (j * 8 + 7)] / src1Ub[i, 0 : 7]
    // src0Ub:[dealRowCount, columnCount], src1Ub:[dealRowCount, FP32_BLOCK_ELEMENT_NUM] dstUb:[dealRowCount,
    // columnCount]
    uint32_t dtypeMask = FP32_REPEAT_ELEMENT_NUM;
    uint32_t dLoop = actualColumnCount / dtypeMask;
    uint32_t dRemain = actualColumnCount % dtypeMask;

    BinaryRepeatParams repeatParamsDiv;
    repeatParamsDiv.src0BlkStride = 1;
    repeatParamsDiv.src1BlkStride = 0;
    repeatParamsDiv.dstBlkStride = 1;
    repeatParamsDiv.src0RepStride = columnCount / FP32_BLOCK_ELEMENT_NUM;
    repeatParamsDiv.src1RepStride = 1;
    repeatParamsDiv.dstRepStride = columnCount / FP32_BLOCK_ELEMENT_NUM;
    uint32_t columnRepeatCount = dLoop;
    if (columnRepeatCount <= dealRowCount) {
        uint32_t offset = 0;
        for (uint32_t i = 0; i < dLoop; i++) {
            Div(dstUb[offset], src0Ub[offset], src1Ub, dtypeMask, dealRowCount, repeatParamsDiv);
            offset += dtypeMask;
        }
    } else {
        BinaryRepeatParams columnRepeatParams;
        columnRepeatParams.src0BlkStride = 1;
        columnRepeatParams.src1BlkStride = 0;
        columnRepeatParams.dstBlkStride = 1;
        columnRepeatParams.src0RepStride = 8; // 列方向上两次repeat起始地址间隔dtypeMask=64个元素，�?个block
        columnRepeatParams.src1RepStride = 0;
        columnRepeatParams.dstRepStride = 8;  // 列方向上两次repeat起始地址间隔dtypeMask=64个元素，�?个block
        uint32_t offset = 0;
        for (uint32_t i = 0; i < dealRowCount; i++) {
            Div(dstUb[offset], src0Ub[offset], src1Ub[i * FP32_BLOCK_ELEMENT_NUM], dtypeMask, columnRepeatCount,
                columnRepeatParams);
            offset += columnCount;
        }
    }
    if (dRemain > 0) {
        Div(dstUb[dLoop * dtypeMask], src0Ub[dLoop * dtypeMask], src1Ub, dRemain, dealRowCount, repeatParamsDiv);
    }
}

template <typename FusedSparseAttentionOverlapTraits>
__aicore__ inline void
FusedSparseAttentionOverlapVectorService<FusedSparseAttentionOverlapTraits>::RowMuls(LocalTensor<T> dstUb, LocalTensor<T> src0Ub, LocalTensor<T> src1Ub,
                                uint32_t dealRowCount, uint32_t columnCount, uint32_t actualColumnCount)
{
    // muls by row, 每行的元素乘以相同的元素
    // dstUb[i, (j * 8) : (j * 8 + 7)] = src0Ub[i, (j * 8) : (j * 8 + 7)] * src1Ub[i, 0 : 7]
    // src0Ub:[dealRowCount, columnCount] src1Ub:[dealRowCount, FP32_BLOCK_ELEMENT_NUM] dstUb:[dealRowCount,
    // columnCount]
    // dealRowCount is repeat times, must be less 256
    uint32_t repeatElementNum = FP32_REPEAT_ELEMENT_NUM;
    uint32_t blockElementNum = FP32_BLOCK_ELEMENT_NUM;

    if constexpr (std::is_same<T, half>::value) {
        // 此限制由于每个repeat至多连续读取256B数据
        repeatElementNum = FP32_REPEAT_ELEMENT_NUM * 2; // 256/4 * 2=128
        blockElementNum = FP32_BLOCK_ELEMENT_NUM * 2;   // 32/4 * 2 = 16
    }

    // 每次只能连续读取256B的数据进行计算，故每次只能处�?56B/sizeof(dType)=
    // 列方向分dLoop次，每次处理8列数�?
    uint32_t dLoop = actualColumnCount / repeatElementNum;
    uint32_t dRemain = actualColumnCount % repeatElementNum;
    // REPEATE_STRIDE_UP_BOUND=256�?此限制由于src0RepStride数据类型为uint8之多256个datablock间距
    if (columnCount < REPEATE_STRIDE_UP_BOUND * blockElementNum) {
        BinaryRepeatParams repeatParams;
        repeatParams.src0BlkStride = 1;
        repeatParams.src1BlkStride = 0;
        repeatParams.dstBlkStride = 1;
        repeatParams.src0RepStride = columnCount / blockElementNum;
        repeatParams.src1RepStride = 1;
        repeatParams.dstRepStride = columnCount / blockElementNum;

        // 如果以列为repeat所处理的次数小于行处理次数，则以列方式处理。反之则以行进行repeat处理
        if (dLoop <= dealRowCount) {
            uint32_t offset = 0;
            for (uint32_t i = 0; i < dLoop; i++) {
                Mul(dstUb[offset], src0Ub[offset], src1Ub, repeatElementNum, dealRowCount, repeatParams);
                offset += repeatElementNum;
            }
        } else {
            BinaryRepeatParams columnRepeatParams;
            columnRepeatParams.src0BlkStride = 1;
            columnRepeatParams.src1BlkStride = 0;
            columnRepeatParams.dstBlkStride = 1;
            columnRepeatParams.src0RepStride = 8; // 列方向上两次repeat起始地址间隔dtypeMask=64个元素，�?个block
            columnRepeatParams.src1RepStride = 0;
            columnRepeatParams.dstRepStride = 8;  // 列方向上两次repeat起始地址间隔dtypeMask=64个元素，�?个block
            for (uint32_t i = 0; i < dealRowCount; i++) {
                Mul(dstUb[i * columnCount], src0Ub[i * columnCount], src1Ub[i * blockElementNum], repeatElementNum,
                    dLoop, columnRepeatParams);
            }
        }

        // 最后一次完成[dealRowCount, dRemain] * [dealRowCount, blockElementNum] 只计算有效部�?
        if (dRemain > 0) {
            Mul(dstUb[dLoop * repeatElementNum], src0Ub[dLoop * repeatElementNum], src1Ub, dRemain, dealRowCount,
                repeatParams);
        }
    } else {
        BinaryRepeatParams repeatParams;
        repeatParams.src0RepStride = 8; // 每个repeat�?56B数据，正�?个datablock
        repeatParams.src0BlkStride = 1;
        repeatParams.src1RepStride = 0;
        repeatParams.src1BlkStride = 0;
        repeatParams.dstRepStride = 8;
        repeatParams.dstBlkStride = 1;
        // 每次计算一行，共计算dealRowCount�?
        for (uint32_t i = 0; i < dealRowCount; i++) {
            // 计算一行中的dLoop个repeat, 每个repeat计算256/block_size 个data_block
            Mul(dstUb[i * columnCount], src0Ub[i * columnCount], src1Ub[i * blockElementNum], repeatElementNum, dLoop,
                repeatParams);
            //  计算一行中的尾�?
            if (dRemain > 0) {
                Mul(dstUb[i * columnCount + dLoop * repeatElementNum],
                    src0Ub[i * columnCount + dLoop * repeatElementNum], src1Ub[i * blockElementNum], dRemain, 1,
                    repeatParams);
            }
        }
    }
}

#endif // FUSED_SPARSE_ATTENTION_OVERLAP_SERVICE_VECTOR_MLA_H
