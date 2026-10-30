// Copyright 2026 KVCache.AI
//
// Licensed under the Apache License, Version 2.0 (the "License");
// you may not use this file except in compliance with the License.
// You may obtain a copy of the License at
//
//     http://www.apache.org/licenses/LICENSE-2.0
//
// Unless required by applicable law or agreed to in writing, software
// distributed under the License is distributed on an "AS IS" BASIS,
// WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
// See the License for the specific language governing permissions and
// limitations under the License.

#ifndef TENT_TPU_TRANSPORT_H_
#define TENT_TPU_TRANSPORT_H_

#include <atomic>
#include <functional>
#include <memory>
#include <mutex>
#include <string>
#include <vector>

#include "tent/common/concurrent/thread_pool.h"
#include "tent/runtime/control_plane.h"
#include "tent/runtime/transport.h"

namespace mooncake {
namespace tent {

struct TpuParams {
    // Threads that run the HBM<->host copies, so the staging pipeline keeps
    // other chunks moving while a copy is in flight. 0 runs each copy on the
    // submitting thread.
    size_t max_concurrent_tasks = 4;
};

struct TpuTask {
    Request request;
    BatchID progress_batch_id{0};
    std::function<void(BatchID)> notify_progress;
    std::atomic<TransferStatusEnum> status_word{TransferStatusEnum::PENDING};
    std::atomic<size_t> transferred_bytes{0};

    TpuTask() = default;
    TpuTask(TpuTask &&other) noexcept
        : request(std::move(other.request)),
          progress_batch_id(other.progress_batch_id),
          notify_progress(std::move(other.notify_progress)),
          status_word(other.status_word.load(std::memory_order_relaxed)),
          transferred_bytes(
              other.transferred_bytes.load(std::memory_order_relaxed)) {}
    TpuTask(const TpuTask &) = delete;
    TpuTask &operator=(const TpuTask &) = delete;
};

struct TpuSubBatch : public Transport::SubBatch {
    std::vector<TpuTask> task_list;
    size_t max_size;
    virtual size_t size() const { return task_list.size(); }
};

// TpuTransport is the local staging executor for TPU: it performs the
// HBM<->host-DRAM hop of a staged transfer by delegating to
// Platform::copy() (which routes to the PJRT adapter for TPU memory). It never
// touches the network — the host<->host hop is carried by RDMA/TCP, and
// ProxyManager chains the two stages (see findStagingPolicy). The copies run
// on a thread pool (transports/tpu/max_concurrent_tasks) by default, so a
// submit can return before its copy completes.
//
// Because TPU HBM is not NIC-addressable, this transport advertises only the
// device<->host capabilities (gpu_to_dram / dram_to_gpu) and leaves gpu_to_gpu
// false so the engine always stages cross-node traffic through host DRAM. It is
// therefore only ever selected for LOCAL_SEGMENT_ID copies.
class TpuTransport : public Transport {
   public:
    TpuTransport();

    ~TpuTransport();

    virtual Status install(std::string &local_segment_name,
                           std::shared_ptr<ControlService> metadata,
                           std::shared_ptr<Topology> local_topology,
                           std::shared_ptr<Config> conf = nullptr);

    virtual Status uninstall();

    virtual Status quiesce() override;

    virtual Status allocateSubBatch(SubBatchRef &batch, size_t max_size);

    virtual Status freeSubBatch(SubBatchRef &batch);

    virtual Status submitTransferTasks(
        SubBatchRef batch, const std::vector<Request> &request_list);

    virtual Status getTransferStatus(SubBatchRef batch, int task_id,
                                     TransferStatus &status);

    virtual Status addMemoryBuffer(BufferDesc &desc,
                                   const MemoryOptions &options);

    virtual Status removeMemoryBuffer(BufferDesc &desc);

    virtual const char *getName() const { return "tpu"; }

   private:
    void startTransfer(TpuTask *task);

    Status copy(const Request &request);

   private:
    bool installed_;
    std::string local_segment_name_;
    std::shared_ptr<Topology> local_topology_;
    std::shared_ptr<ControlService> metadata_;
    std::shared_ptr<Config> conf_;
    TpuParams params_;
    std::mutex lifecycle_mutex_;
    std::unique_ptr<ThreadPool> thread_pool_;
    std::atomic<bool> shutting_down_{false};
};

}  // namespace tent
}  // namespace mooncake

#endif  // TENT_TPU_TRANSPORT_H_
