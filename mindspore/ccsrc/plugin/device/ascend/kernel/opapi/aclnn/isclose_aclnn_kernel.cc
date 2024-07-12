/**
 * Copyright 2024 Huawei Technologies Co., Ltd
 *
 * Licensed under the Apache License, Version 2.0 (the "License");
 * you may not use this file except in compliance with the License.
 * You may obtain a copy of the License at
 *
 * http://www.apache.org/licenses/LICENSE-2.0
 *
 * Unless required by applicable law or agreed to in writing, software
 * distributed under the License is distributed on an "AS IS" BASIS,
 * WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
 * See the License for the specific language governing permissions and
 * limitations under the License.
 */
#include "plugin/device/ascend/kernel/opapi/aclnn/isclose_aclnn_kernel.h"
#include <vector>
#include <memory>
#include <functional>
#include "ir/tensor.h"
#include "runtime/device/kernel_runtime.h"
#include "transform/acl_ir/op_api_convert.h"

namespace mindspore {
namespace kernel {

void IsCloseAscend::GetWorkSpaceInfo(const std::vector<KernelTensor *> &inputs,
                                     const std::vector<KernelTensor *> &outputs) {
  rtol_ = static_cast<double>(transform::ConvertKernelTensor<float>(inputs[kIndex2]));
  atol_ = static_cast<double>(transform::ConvertKernelTensor<float>(inputs[kIndex3]));
  equal_nan_ = transform::ConvertKernelTensor<bool>(inputs[kIndex4]);

  GetWorkspaceForResize(inputs[kIndex0], inputs[kIndex1], rtol_, atol_, equal_nan_, outputs[kIndex0]);
}

bool IsCloseAscend::Launch(const std::vector<KernelTensor *> &inputs, const std::vector<KernelTensor *> &workspace,
                           const std::vector<KernelTensor *> &outputs, void *stream_ptr) {
  MS_EXCEPTION_IF_NULL(stream_ptr);
  RunOp(stream_ptr, workspace, inputs[kIndex0], inputs[kIndex1], rtol_, atol_, equal_nan_, outputs[kIndex0]);
  return true;
}

MS_ACLNN_KERNEL_FACTORY_REG(IsClose, IsCloseAscend);
}  // namespace kernel
}  // namespace mindspore
