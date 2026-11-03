/**
 * Copyright (c) 2026 Huawei Technologies Co., Ltd.
 * This program is free software, you can redistribute it and/or modify it under the terms and conditions of
 * CANN Open Software License Agreement Version 2.0 (the "License").
 * Please refer to the License for details. You may not use this file except in compliance with the License.
 * THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND, EITHER EXPRESS OR IMPLIED,
 * INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY, OR FITNESS FOR A PARTICULAR PURPOSE.
 * See LICENSE in the root of the software repository for the full text of the License.
 */

#include "checker.h"

#include <algorithm>
#include <chrono>
#include <cstdint>
#include <map>
#include <memory>
#include <queue>
#include <set>
#include <sstream>
#include <string>
#include <utility>
#include <vector>

#include "dump_v3/dump_v3_dag.h"
#include "dump_v3/dump_v3_manager.h"
#include "framework/task_graph_generator_v3/task_graph_generator_v3.h"
#include "framework/task_graph_generator_v3/task_graph_mem_conflict_v3.h"
#include "framework/task_graph_generator_v3/task_graph_sync_conflict_v3.h"
#include "framework/task_graph_generator_v3/task_graph_semantic_check_v3.h"
#include "framework/task_graph_generator_v3/task_graph_single_task_check_v3.h"
#include "framework/task_graph_generator_v3/task_meta_translator_v3.h"
#include "sim_log.h"
#include "log.h"
#include "storage_manager.h"

using namespace std;

namespace HcclSim {
namespace {
    using V3TaskNode = TaskGraphGeneratorV3::TaskNode;
    using V3StageClock = std::chrono::steady_clock;
    constexpr uint64_t V3_NS_PER_MS = 1000000ULL;

    uint64_t ElapsedV3Ns(V3StageClock::time_point start, V3StageClock::time_point end)
    {
        return static_cast<uint64_t>(std::chrono::duration_cast<std::chrono::nanoseconds>(end - start).count());
    }

    constexpr bool ENABLE_V3_MEM_CONFLICT_CHECK = true;
    constexpr bool ENABLE_V3_SEMANTIC_CHECK = true;

    class V3StageTimer {
    public:
        explicit V3StageTimer(const char* stage) : stage_(stage), start_(V3StageClock::now()) {}

        ~V3StageTimer()
        {
            const uint64_t elapsedNs = ElapsedV3Ns(start_, V3StageClock::now());
            if (extraInfo_.empty()) {
                HCCL_VM_INFO(
                    "CheckerV3 stage finished, stage={}, status={}, costMs={}", stage_, status_,
                    elapsedNs / V3_NS_PER_MS);
                return;
            }
            HCCL_VM_INFO(
                "CheckerV3 stage finished, stage={}, status={}, costMs={}, {}", stage_, status_,
                elapsedNs / V3_NS_PER_MS, extraInfo_);
        }

        void SetStatus(const char* status) { status_ = status; }

        void SetExtraInfo(const std::string& extraInfo) { extraInfo_ = extraInfo; }

    private:
        const char* stage_{nullptr};
        const V3StageClock::time_point start_;
        const char* status_{"failed"};
        std::string extraInfo_;
    };

    bool IsV3Boundary(const V3TaskNode* node, TaskGraphGeneratorV3::BoundaryType boundaryType)
    {
        if (node == nullptr) {
            return false;
        }
        if (node->GetType() == TaskGraphGeneratorV3::TaskType::START) {
            auto* start = dynamic_cast<const TaskGraphGeneratorV3::TaskStart*>(node);
            return start != nullptr && start->GetBoundaryType() == boundaryType;
        }
        if (node->GetType() == TaskGraphGeneratorV3::TaskType::END) {
            auto* end = dynamic_cast<const TaskGraphGeneratorV3::TaskEnd*>(node);
            return end != nullptr && end->GetBoundaryType() == boundaryType;
        }
        return false;
    }

    bool IsAivTaskType(TaskGraphGeneratorV3::TaskType type)
    {
        switch (type) {
            case TaskGraphGeneratorV3::TaskType::AIV_GRAPH:
            case TaskGraphGeneratorV3::TaskType::AIV_SET_FLAG:
            case TaskGraphGeneratorV3::TaskType::AIV_WAIT_FLAG:
            case TaskGraphGeneratorV3::TaskType::AIV_PIPE_BARRIER:
            case TaskGraphGeneratorV3::TaskType::AIV_SYNC_ALL:
            case TaskGraphGeneratorV3::TaskType::AIV_SEND_FLAG:
            case TaskGraphGeneratorV3::TaskType::AIV_RECV_FLAG:
                return true;
            default:
                return false;
        }
    }

    bool IsAivDataTaskType(TaskGraphGeneratorV3::TaskType type)
    {
        switch (type) {
            case TaskGraphGeneratorV3::TaskType::TRANS_MEM:
            case TaskGraphGeneratorV3::TaskType::BATCH_TRANS_MEM:
            case TaskGraphGeneratorV3::TaskType::REDUCE:
            case TaskGraphGeneratorV3::TaskType::BATCH_REDUCE:
                return true;
            default:
                return false;
        }
    }

    bool IsAivSyntheticDataNode(const V3TaskNode* node)
    {
        if (node == nullptr || !IsAivDataTaskType(node->GetType()) || node->HasCcuTrace()) {
            return false;
        }
        const auto& loc = node->GetPosition();
        return loc.streamId == TaskGraphGeneratorV3::INVALID_STREAM_ID
               && loc.queueId != TaskGraphGeneratorV3::INVALID_QUEUE_ID;
    }

    bool IsAivDagLogNode(const V3TaskNode* node)
    {
        if (node == nullptr) {
            return false;
        }
        return IsAivTaskType(node->GetType()) || IsAivSyntheticDataNode(node)
               || IsV3Boundary(node, TaskGraphGeneratorV3::BoundaryType::AIV_SUB_GRAPH);
    }

    std::unique_ptr<TaskGraphGeneratorV3::TaskGraphGeneratorV3> GenGraphV3FromTaskMeta()
    {
        V3StageTimer timer("GenGraph");
        StorageManager& storage = StorageManager::GetInstance();
        TaskGraphGeneratorV3::TaskMetaTranslatorV3 taskMetaTranslatorV3;
        // V3 主流程入口：
        // 1. 先把 task meta 翻译成中间节点；
        // 2. 做一次从流合法性检查；
        // 3. 再生成 V3 图并在日志里记录成图/CCU 展开耗时。
        {
            V3StageTimer translateTimer("TranslateTask");
            HcclResult ret = taskMetaTranslatorV3.Translate(storage, TaskGraphGeneratorV3::INVALID_OPERATOR_ID);
            if (ret != HCCL_SUCCESS) {
                HCCL_VM_WARN(
                    "Failed to translate one task into the V3 internal format, V3 graph generation is "
                    "stopped, ret={}",
                    static_cast<uint32_t>(ret));
                return nullptr;
            }
            translateTimer.SetStatus("success");
        }

        HcclResult ret = HCCL_SUCCESS;
        auto translatedNodes = taskMetaTranslatorV3.TakeNodes();
        auto translatedTaskQueues = taskMetaTranslatorV3.TakeTaskQueues();
        ret = TaskGraphGeneratorV3::CheckSlaveTaskQueue(translatedNodes, translatedTaskQueues);
        if (ret != HCCL_SUCCESS) {
            HCCL_VM_WARN(
                "Slave-stream check failed, V3 graph generation is stopped, ret={}", static_cast<uint32_t>(ret));
            return nullptr;
        }
        std::unique_ptr<TaskGraphGeneratorV3::TaskGraphGeneratorV3> graphGeneratorV3(
            new (std::nothrow) TaskGraphGeneratorV3::TaskGraphGeneratorV3);
        if (graphGeneratorV3 == nullptr) {
            HCCL_VM_WARN("Failed to create the V3 graph generator object");
            return nullptr;
        }

        {
            V3StageTimer buildGraphTimer("BuildGraph");
            ret = graphGeneratorV3->GenGraph(std::move(translatedNodes), std::move(translatedTaskQueues));
            if (ret != HCCL_SUCCESS) {
                HCCL_VM_WARN(
                    "Failed to build the graph from translated tasks, ret={}, rankCount={}, nodeCount={}",
                    static_cast<uint32_t>(ret), graphGeneratorV3->GetTaskQueues().size(),
                    graphGeneratorV3->GetNodes().size());
                return nullptr;
            }
            buildGraphTimer.SetStatus("success");
        }
        const auto& ccuExpandStats = graphGeneratorV3->GetCcuExpandStats();
        const auto& aivExpandStats = graphGeneratorV3->GetAivExpandStats();
        std::ostringstream timerExtraInfo;
        timerExtraInfo << "taskNodeCount=" << graphGeneratorV3->GetNodes().size()
                       << ", mainStartNodeId=" << graphGeneratorV3->GetMainStartNodeId()
                       << ", aivExpandTotalMs=" << (aivExpandStats.totalExpandNs / V3_NS_PER_MS)
                       << ", aivGraphCount=" << aivExpandStats.graphCount
                       << ", ccuExpandTotalMs=" << (ccuExpandStats.totalExpandNs / V3_NS_PER_MS)
                       << ", ccuGraphCount=" << ccuExpandStats.graphCount;
        timer.SetExtraInfo(timerExtraInfo.str());
        timer.SetStatus("success");
        return graphGeneratorV3;
    }

    std::vector<const V3TaskNode*> BfsGraphV3(const V3TaskNode* start)
    {
        std::vector<const V3TaskNode*> result;
        if (start == nullptr) {
            return result;
        }

        std::queue<const V3TaskNode*> nodeQue;
        std::set<const V3TaskNode*> visited;
        nodeQue.push(start);
        visited.insert(start);

        while (!nodeQue.empty()) {
            const V3TaskNode* currNode = nodeQue.front();
            nodeQue.pop();
            result.push_back(currNode);

            for (const V3TaskNode* childNode : currNode->GetChildren()) {
                if (childNode == nullptr || visited.count(childNode) != 0) {
                    continue;
                }
                visited.insert(childNode);
                nodeQue.push(childNode);
            }
        }

        return result;
    }

    const char* TaskTypeKeyName(TaskGraphGeneratorV3::TaskType type)
    {
        switch (type) {
            case TaskGraphGeneratorV3::TaskType::TRANS_MEM:
                return "TRANS_MEM";
            case TaskGraphGeneratorV3::TaskType::BATCH_TRANS_MEM:
                return "BATCH_TRANS_MEM";
            case TaskGraphGeneratorV3::TaskType::REDUCE:
                return "REDUCE";
            case TaskGraphGeneratorV3::TaskType::BATCH_REDUCE:
                return "BATCH_REDUCE";
            case TaskGraphGeneratorV3::TaskType::RECORD:
                return "RECORD";
            case TaskGraphGeneratorV3::TaskType::WAIT:
                return "WAIT";
            case TaskGraphGeneratorV3::TaskType::CCU_GRAPH:
                return "CCU_GRAPH";
            case TaskGraphGeneratorV3::TaskType::AIV_GRAPH:
                return "AIV_GRAPH";
            case TaskGraphGeneratorV3::TaskType::AIV_SET_FLAG:
                return "AIV_SET_FLAG";
            case TaskGraphGeneratorV3::TaskType::AIV_WAIT_FLAG:
                return "AIV_WAIT_FLAG";
            case TaskGraphGeneratorV3::TaskType::AIV_PIPE_BARRIER:
                return "AIV_PIPE_BARRIER";
            case TaskGraphGeneratorV3::TaskType::AIV_SYNC_ALL:
                return "AIV_SYNC_ALL";
            case TaskGraphGeneratorV3::TaskType::AIV_SEND_FLAG:
                return "AIV_SEND_FLAG";
            case TaskGraphGeneratorV3::TaskType::AIV_RECV_FLAG:
                return "AIV_RECV_FLAG";
            case TaskGraphGeneratorV3::TaskType::START:
                return "START";
            case TaskGraphGeneratorV3::TaskType::END:
                return "END";
            case TaskGraphGeneratorV3::TaskType::SYNC_STREAM:
                return "SYNC_STREAM";
            case TaskGraphGeneratorV3::TaskType::MODEL_EXEC_START:
                return "MODEL_EXEC_START";
            case TaskGraphGeneratorV3::TaskType::MODEL_EXEC_START_SUB:
                return "MODEL_EXEC_START_SUB";
            case TaskGraphGeneratorV3::TaskType::MODEL_EXEC_END_SUB:
                return "MODEL_EXEC_END_SUB";
            case TaskGraphGeneratorV3::TaskType::MODEL_EXEC_END:
                return "MODEL_EXEC_END";
            default:
                return "INVALID";
        }
    }

    std::string FormatV3NodeIdList(const std::vector<V3TaskNode*>& nodes)
    {
        std::ostringstream os;
        os << "[";
        bool firstNode = true;
        for (const V3TaskNode* node : nodes) {
            if (node == nullptr) {
                continue;
            }
            if (!firstNode) {
                os << ",";
            }
            firstNode = false;
            os << node->GetNodeId();
        }
        os << "]";
        return os.str();
    }

    std::string MakeAivDagTaskLogLine(const V3TaskNode* node, size_t bfsIndex)
    {
        if (node == nullptr) {
            return "node=null";
        }
        const auto& loc = node->GetPosition();
        std::ostringstream os;
        os << "bfsIndex=" << bfsIndex << ", nodeId=" << node->GetNodeId()
           << ", taskType=" << TaskTypeKeyName(node->GetType()) << ", rankId=" << loc.rankId
           << ", streamId=" << loc.streamId << ", queueId=" << loc.queueId
           << ", parentNodeIds=" << FormatV3NodeIdList(node->GetParents())
           << ", childNodeIds=" << FormatV3NodeIdList(node->GetChildren()) << ", detail=" << node->Describe();
        return os.str();
    }

    size_t LogAivExpandedDagTasks(const std::vector<const V3TaskNode*>& v3BfsNodes)
    {
        size_t aivTaskCount = 0;
        for (size_t index = 0; index < v3BfsNodes.size(); ++index) {
            const V3TaskNode* node = v3BfsNodes[index];
            if (!IsAivDagLogNode(node)) {
                continue;
            }
            HCCL_VM_DEBUG("Expanded AIV DAG node detail, {}", MakeAivDagTaskLogLine(node, index));
            ++aivTaskCount;
        }
        HCCL_VM_DEBUG("Finished dumping expanded AIV DAG node details, taskCount={}", aivTaskCount);
        return aivTaskCount;
    }

    void LogGraphV3Dag(const V3TaskNode* start)
    {
        if (start == nullptr) {
            HCCL_VM_WARN("Skip DAG dump because the graph start node is null");
            return;
        }

        const auto v3BfsNodes = BfsGraphV3(start);
        LogAivExpandedDagTasks(v3BfsNodes);
    }

    void LogGraphV3Sqe(const TaskGraphGeneratorV3::TaskGraphGeneratorV3& graph)
    {
        const auto& translatedTaskQueues = graph.GetTaskQueues();
        const auto& translatedNodes = graph.GetNodes();

        uint32_t rankIdx = 0;
        uint32_t rankNum = 0;
        for (const auto& iter : translatedTaskQueues) {
            rankIdx = iter.first;
            ++rankNum;
            HCCL_VM_INFO("=======================================================");
            HCCL_VM_INFO("rankId is : {:d}", rankIdx);
            const TaskGraphGeneratorV3::RankNodeQueues& taskQueue = iter.second;
            for (size_t i = 0; i < taskQueue.size(); ++i) {
                if (taskQueue[i].empty()) {
                    continue;
                }

                uint32_t taskIdx = 0;
                HCCL_VM_INFO(
                    "streamIdx : {:d}, taskNum : {:d}", static_cast<uint32_t>(i),
                    static_cast<uint32_t>(taskQueue[i].size()));
                HCCL_VM_INFO("-------------------------------------------------------");
                for (const auto& nodeId : taskQueue[i]) {
                    if (nodeId < 0 || static_cast<size_t>(nodeId) >= translatedNodes.size()
                        || translatedNodes[static_cast<size_t>(nodeId)] == nullptr) {
                        HCCL_VM_WARN("rankIdx:{:d}, taskIdx:{:d}, invalid nodeId:{:d}", rankIdx, taskIdx, nodeId);
                        ++taskIdx;
                        continue;
                    }

                    const std::unique_ptr<TaskGraphGeneratorV3::TaskNode>& task
                        = translatedNodes[static_cast<size_t>(nodeId)];
                    const std::string tempStr = task->Describe();
                    HCCL_VM_INFO("rankIdx:{:d}, taskIdx:{:d}, {:s}", rankIdx, taskIdx, tempStr);
                    ++taskIdx;
                }
            }
        }
        HCCL_VM_INFO("Finished logging V3 SQE task queues, rankNum={:d}", rankNum);
    }

    /**
     * @brief 由任务队列构建"队列任务身份表":下标为 nodeId,非 0 表示该节点是任务队列中的原始任务。
     * @param taskQueues 输入：全部 rank 的任务队列(流向量)。
     * @return 身份表,长度为最大队列 nodeId + 1;表内未覆盖的节点(如 CCU/AIV 展开内部节点)
     *         一律视为非队列任务。
     * @note 内存冲突检查的"同队列剪枝"只允许剪两个端点都是原始队列任务的候选对,
     *       因为构图器只对队列内相邻任务连了顺序边;展开内部节点之间无顺序边,不能被剪。
     */
    std::vector<uint8_t> BuildQueueEntryFlags(const TaskGraphGeneratorV3::AllRankNodeQueues& taskQueues)
    {
        int64_t maxNodeId = 0;
        for (const auto& rankEntry : taskQueues) {
            for (const auto& stream : rankEntry.second) {
                for (const TaskGraphGeneratorV3::NodeId nodeId : stream) {
                    maxNodeId = std::max<int64_t>(maxNodeId, nodeId);
                }
            }
        }
        std::vector<uint8_t> flags(static_cast<size_t>(maxNodeId) + 1U, 0U);
        for (const auto& rankEntry : taskQueues) {
            for (const auto& stream : rankEntry.second) {
                for (const TaskGraphGeneratorV3::NodeId nodeId : stream) {
                    if (nodeId >= 0) {
                        flags[static_cast<size_t>(nodeId)] = 1U;
                    }
                }
            }
        }
        return flags;
    }

    HcclResult CheckGraphV3TaskMem(const V3TaskNode* start)
    {
        V3StageTimer timer("SingleTaskCheck");
        if (start == nullptr) {
            HCCL_VM_WARN("Skip single-task memory check because the graph start node is null");
            timer.SetStatus("skipped");
            return HCCL_SUCCESS;
        }

        // 单 task 校验只看每个节点自身的 src/dst 描述是否合法，不依赖跨节点语义。
        TaskGraphGeneratorV3::SingleTaskCheckStats stats;
        HcclResult ret = TaskGraphGeneratorV3::CheckTaskMem(start, &stats);
        std::ostringstream extraInfo;
        extraInfo << "nodeCount=" << stats.nodeCount << ", dataTaskNodeCount=" << stats.dataTaskNodeCount;
        if (TaskGraphGeneratorV3::g_checkerAivUbBufferSize != 0
            || TaskGraphGeneratorV3::g_checkerAivCommInfoSize != 0) {
            extraInfo << ", aivUbBufferSize=" << TaskGraphGeneratorV3::g_checkerAivUbBufferSize
                      << ", aivCommInfoSize=" << TaskGraphGeneratorV3::g_checkerAivCommInfoSize;
        }
        timer.SetExtraInfo(extraInfo.str());
        timer.SetStatus(ret == HCCL_SUCCESS ? "success" : "failed");
        return ret;
    }

    HcclResult CheckGraphV3MemConflict(const V3TaskNode* start, const std::vector<uint8_t>* queueEntryFlags)
    {
        V3StageTimer timer("MemConflict");
        if (start == nullptr) {
            HCCL_VM_WARN("Skip memory-conflict check because the graph start node is null");
            timer.SetStatus("skipped");
            return HCCL_SUCCESS;
        }

        // 内存冲突校验会先收集所有数据搬运节点的访问区间，再按地址桶扫描重叠候选。
        TaskGraphGeneratorV3::MemConflictCheckStats stats;
        HcclResult ret = TaskGraphGeneratorV3::CheckDataMoveTaskMemConflict(start, queueEntryFlags, &stats);
        std::ostringstream extraInfo;
        extraInfo << "nodeCount=" << stats.nodeCount << ", dataTaskNodeCount=" << stats.dataTaskNodeCount
                  << ", processedDataTaskNodeCount=" << stats.processedDataTaskNodeCount
                  << ", accessIntervalCount=" << stats.accessIntervalCount
                  << ", memoryBucketCount=" << stats.memoryBucketCount
                  << ", overlapCandidatePairCount=" << stats.overlapCandidatePairCount
                  << ", sameStreamPrunedPairCount=" << stats.sameStreamPrunedPairCount
                  << ", duplicatePairPrunedCount=" << stats.duplicatePairPrunedCount
                  << ", orderedCandidatePairs=" << stats.orderedCandidatePairCount
                  << ", parallelCandidatePairs=" << stats.parallelCandidatePairCount;
        timer.SetExtraInfo(extraInfo.str());
        timer.SetStatus(ret == HCCL_SUCCESS ? "success" : "failed");
        return ret;
    }

    HcclResult CheckGraphV3SyncConflict(const V3TaskNode* start)
    {
        V3StageTimer timer("SyncConflict");
        if (start == nullptr) {
            HCCL_VM_WARN("Skip sync-conflict check because the graph start node is null");
            timer.SetStatus("skipped");
            return HCCL_SUCCESS;
        }

        TaskGraphGeneratorV3::SyncConflictCheckStats stats;
        HcclResult ret = TaskGraphGeneratorV3::CheckSyncResourceConflict(start, &stats);
        std::ostringstream extraInfo;
        extraInfo << "originalNodeCount=" << stats.originalNodeCount << ", copiedNodeCount=" << stats.copiedNodeCount
                  << ", copiedEdgeCount=" << stats.copiedEdgeCount
                  << ", resourceBucketCount=" << stats.resourceBucketCount << ", pairCount=" << stats.pairCount
                  << ", checkedBucketCount=" << stats.checkedBucketCount << ", conflictCount=" << stats.conflictCount;
        timer.SetExtraInfo(extraInfo.str());
        timer.SetStatus(ret == HCCL_SUCCESS ? "success" : "failed");
        return ret;
    }

    // 方案二（屏障真等）配套降级判定：reduce 类算子（AllReduce/Reduce/ReduceScatter/ReduceScatterV）
    // 且（64bit 数据类型 或 PROD 归约）——恰为 hccl LocalReduce→AicpuReduce 分支的命中条件
    // （alg_data_trans_wrapper.cc:905）。该类算子的归约由 device 进程内联 CPU 计算完成，
    // 不产生 REDUCE 任务制品（方案二固有盲区，设计文档 §9.2），任务图缺失归约节点，
    // 语义校验（按 DAG 模拟内存来源、校验输出布局/归并来源）必然报"归并来源不足"
    // （ErrorCode 409 类）——属预期盲区而非业务错误，故跳过语义校验；
    // 单任务内存/同步资源/内存冲突等校验不受影响、照常执行。
    bool IsReduceSemanticBlindSpotOp(const CheckerParam& param)
    {
        const bool isReduceFamily = (param.cmdType == HcclCMDType::HCCL_CMD_ALLREDUCE)
                                    || (param.cmdType == HcclCMDType::HCCL_CMD_REDUCE)
                                    || (param.cmdType == HcclCMDType::HCCL_CMD_REDUCE_SCATTER)
                                    || (param.cmdType == HcclCMDType::HCCL_CMD_REDUCE_SCATTER_V);
        if (!isReduceFamily) {
            return false;
        }
        const bool is64BitType = (param.dataType == HCCL_DATA_TYPE_INT64) || (param.dataType == HCCL_DATA_TYPE_UINT64)
                                 || (param.dataType == HCCL_DATA_TYPE_FP64);
        const bool isProdOp = (param.reduceType == HcclReduceOp::HCCL_REDUCE_PROD);
        return is64BitType || isProdOp;
    }

    HcclResult CheckGraphV3Semantic(const V3TaskNode* start)
    {
        V3StageTimer timer("SemanticCheck");
        if (start == nullptr) {
            HCCL_VM_WARN("Skip semantic check because the graph start node is null");
            timer.SetStatus("skipped");
            return HCCL_SUCCESS;
        }

        // 按需降级（IsReduceSemanticBlindSpotOp 注释）：64bit/PROD 的 reduce 类算子跳过语义校验。
        const CheckerParam opParam = StorageManager::GetInstance().GetCheckerParam();
        if (IsReduceSemanticBlindSpotOp(opParam)) {
            HCCL_VM_WARN(
                "[SemanticCheckSkip] 当前算子为 reduce 类且命中 64bit 数据类型或 PROD 归约"
                "（cmdType={}, dataType={}, reduceType={}）：该场景下归约由 device 侧 AICPU 内联计算完成，"
                "缺少 REDUCE 的 SQE 任务（任务图不含归约节点），无法进行数据流归并推演，"
                "故跳过语义校验流程；单任务内存/同步资源/内存冲突校验仍正常执行。",
                static_cast<uint32_t>(opParam.cmdType), static_cast<uint32_t>(opParam.dataType),
                static_cast<uint32_t>(opParam.reduceType));
            timer.SetStatus("skipped");
            timer.SetExtraInfo("reason=missing-reduce-sqe-task(64bit-or-PROD)");
            return HCCL_SUCCESS;
        }

        // 语义校验按 DAG 依赖逐节点模拟内存来源，最后再校验各 rank 输出布局。
        TaskGraphGeneratorV3::SemanticCheckStats stats;
        HcclResult ret = TaskGraphGeneratorV3::CheckSemantics(start, &stats);
        // DISABLED 但 detail 非空表示“请求了 strict 而算子不在契约内”，也需要可见。
        if (stats.reduceOrder.status != TaskGraphGeneratorV3::ReduceOrderStatus::DISABLED
            || !stats.reduceOrder.detail.empty()) {
            HCCL_VM_INFO(
                "ReduceOrder check result={}, detail={}",
                TaskGraphGeneratorV3::DescribeReduceOrderStatus(stats.reduceOrder.status), stats.reduceOrder.detail);
        }
        std::ostringstream extraInfo;
        extraInfo << "handledNodeCount=" << stats.handledNodeCount << ", rankCount=" << stats.rankCount
                  << ", normalSemanticCount=" << stats.normalSemanticCount
                  << ", normalSemanticBytes=" << stats.normalSemanticBytes << ", msBucketCount=" << stats.msBucketCount;
        extraInfo << ", reduceOrder=" << TaskGraphGeneratorV3::DescribeReduceOrderStatus(stats.reduceOrder.status)
                  << ", reduceOrderBlocks=" << stats.reduceOrder.outputSpans
                  << ", reduceOrderExprNodes=" << stats.reduceOrder.expressionNodes;
        timer.SetExtraInfo(extraInfo.str());
        timer.SetStatus(ret == HCCL_SUCCESS ? "success" : "failed");
        return ret;
    }
} // namespace

HcclResult GenAndCheckGraphV3()
{
    auto graphGeneratorV3 = GenGraphV3FromTaskMeta();
    if (graphGeneratorV3 == nullptr) {
        return HCCL_E_PTR;
    }
    const HcclResult dumpRet = DumpV3Dag(*graphGeneratorV3);
    if (dumpRet != HCCL_SUCCESS) {
        HCCL_VM_WARN("Failed to dump the V3 DAG, ret={}", static_cast<uint32_t>(dumpRet));
    }
    const V3TaskNode* dummyStartV3 = graphGeneratorV3->GetMainStartNode();
    // 队列任务身份表:供内存冲突检查的"同队列剪枝"区分原始队列任务与 CCU/AIV 展开内部节点。
    const std::vector<uint8_t> queueEntryFlags = BuildQueueEntryFlags(graphGeneratorV3->GetTaskQueues());
    // 打印sqe
    // 1024 卡场景逐 task 打印(Describe()+INFO)量达百万级，暂时注释；需要时放开。
    // LogGraphV3Sqe(*graphGeneratorV3);
    // 打印dag task任务
    // LogGraphV3Dag 内部会先对整个 DAG 做一次 BFS（std::set visited + 全量节点 vector），
    // 该遍历与日志级别无关、开销随节点数增长（6M 节点量级），暂时注释；需要时放开。
    // LogGraphV3Dag(dummyStartV3);

    // V3 检查顺序与日志阶段保持一致：
    // 成图 -> 单 task 内存校验 -> 同步资源校验 -> 内存冲突校验 -> 语义校验。
    CHK_RET(CheckGraphV3TaskMem(dummyStartV3));
    CHK_RET(CheckGraphV3SyncConflict(dummyStartV3));
    if (ENABLE_V3_MEM_CONFLICT_CHECK) {
        CHK_RET(CheckGraphV3MemConflict(dummyStartV3, &queueEntryFlags));
    }
    if (ENABLE_V3_SEMANTIC_CHECK) {
        CHK_RET(CheckGraphV3Semantic(dummyStartV3));
    }
    return HCCL_SUCCESS;
}
} // namespace HcclSim
