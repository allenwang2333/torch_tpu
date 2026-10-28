/*
 * Copyright 2025 Google LLC
 *
 * Licensed under the Apache License, Version 2.0 (the "License");
 * you may not use this file except in compliance with the License.
 * You may obtain a copy of the License at
 *
 *     http://www.apache.org/licenses/LICENSE-2.0
 *
 * Unless required by applicable law or agreed to in writing, software
 * distributed under the License is distributed on an "AS IS" BASIS,
 * WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
 * See the License for the specific language governing permissions and
 * limitations under the License.
 */

#include "csrc/ops/copy_from/cpu_to_tpu.h"

#include <cstdint>
#include <memory>
#include <optional>
#include <utility>
#include <vector>

#include "ATen/core/ATen_fwd.h"
#include "ATen/core/TensorBody.h"
#include "absl/log/absl_log.h"
#include "absl/status/status.h"
#include "c10/core/TensorOptions.h"
#include "csrc/common/error_utils.h"
#include "csrc/common/layout_utils.h"
#include "csrc/common/to_string.h"
#include "csrc/eager/device_buffer.h"
#include "csrc/eager/events_queue.h"
#include "csrc/eager/materialize.h"
#include "csrc/eager/structured_log_buffer.h"
#include "csrc/eager/tensor_to_buffer.h"
#include "csrc/ops/copy_from/copy_common.h"
#include "csrc/pjrt/pjrt_transfer.h"
#include "torch/headeronly/core/MemoryFormat.h"
#include "xla/xla_data.pb.h"

namespace torch_tpu {

absl::Status CopyCpuToTpu(const at::Tensor& src, const at::Tensor& dest,
                          TransferSyncMode transfer_sync_mode) {
  ABSL_VLOG(1) << "[AtenCopyFrom] CPU -> TPU copy path for "
               << ToString(src, "src");
  if (src.numel() == 0) {
    // Copying nothing is a no-op.
    return absl::OkStatus();
  }

  // Ensure the source tensor has the correct dtype and is contiguous.
  at::Tensor effective_src = src;
  if (src.scalar_type() != dest.scalar_type() || !src.is_contiguous()) {
    effective_src = src.to(at::TensorOptions()
                               .dtype(dest.scalar_type())
                               .memory_format(at::MemoryFormat::Contiguous),
                           /*non_blocking=*/false, /*copy=*/true);
  }
  if (transfer_sync_mode == TransferSyncMode::kEagerNonBlocking &&
      effective_src.data_ptr() != src.data_ptr()) {
    // If to() created a copy, then effective_src will be
    // dropped at the end of this function, invalidating the non-blocking
    // copy. We must do a blocking copy to avoid this.
    // TODO(bawilson): implement a non-blocking copy using a CPU->TPU->TPU path
    transfer_sync_mode = TransferSyncMode::kEagerBlocking;
  }
  // A blocking host-to-device copy waits only for its own transfer. Waiting
  // for the whole stream makes every small blocking upload in a serving loop
  // (e.g. vLLM TorchTPU) wait for all queued work, which slows decode on
  // TPU v4 by about 40%. The new buffer is not used by any queued program,
  // so stream order does not matter for it.
  if (transfer_sync_mode == TransferSyncMode::kEagerBlocking) {
    transfer_sync_mode = TransferSyncMode::kIsolated;
  }

  TT_ASSIGN_OR_RETURN(TpuLayout tpu_layout, ResolveTpuLayout(effective_src));

  // NOTE: we are intentionally using Tensor::data_ptr() here,
  // and **not** Tensor::storage().data_ptr().get().
  // On CPU, Tensor::data_ptr() will account for the storage offset, while
  // Tensor::storage().data_ptr().get() will not.
  const void* host_data = effective_src.data_ptr();
  // A non-blocking transfer reads the host data after this function returns,
  // but the caller can free `src` at once, e.g.
  // `torch.tensor(...).to("tpu", non_blocking=True)`. Stage the data in a
  // buffer that the transfer owns until it completes.
  std::vector<uint8_t> staging;
  if (transfer_sync_mode == TransferSyncMode::kEagerNonBlocking) {
    const auto* begin = static_cast<const uint8_t*>(host_data);
    staging.assign(begin, begin + effective_src.nbytes());
    host_data = staging.data();
  }
  TT_ASSIGN_OR_RETURN(
      DeviceBufferRef tpu_buf,
      TpuMallocAndMemcpyHtoD(host_data, tpu_layout.element_type,
                             tpu_layout.sizes, std::move(staging)));
  if (transfer_sync_mode == TransferSyncMode::kIsolated) {
    // Block until the transfer completes, assign the buffer, and return without
    // touching any streams.
    TT_RETURN_IF_ERROR(AdaptXlaError(
        tpu_buf.Synchronize(),
        /* context= */ "failed to copy buffer from host to device"));
    TT_RETURN_IF_ERROR(AssignBufferToAtTensor(std::move(tpu_buf), dest));
    return absl::OkStatus();
  }

  // Record the transfer on the stream in either kEagerBlocking or
  // kEagerNonBlocking mode, but only block if kEagerBlocking.
  RecordAsyncHostToDevice(tpu_buf);
  TT_RETURN_IF_ERROR(AssignBufferToAtTensor(std::move(tpu_buf), dest));

  if (transfer_sync_mode == TransferSyncMode::kEagerBlocking) {
    TT_ASSIGN_OR_RETURN(
        std::shared_ptr<EventSnapshot> snapshot,
        MaterializeCurrentStream(MaterializationReason::kCpuTransfer).Await());
    TT_RETURN_IF_ERROR(snapshot->Synchronize());
    TT_RETURN_IF_ERROR(SyncAndReturnStickyError());
  }
  return absl::OkStatus();
}

}  // namespace torch_tpu
