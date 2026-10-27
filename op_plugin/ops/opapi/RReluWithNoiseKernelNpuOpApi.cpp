// Copyright (c) 2023 Huawei Technologies Co., Ltd
// All rights reserved.
//
// Licensed under the BSD 3-Clause License  (the "License");
// you may not use this file except in compliance with the License.
// You may obtain a copy of the License at
//
// https://opensource.org/licenses/BSD-3-Clause
//
// Unless required by applicable law or agreed to in writing, software
// distributed under the License is distributed on an "AS IS" BASIS,
// WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
// See the License for the specific language governing permissions and
// limitations under the License.

#include "op_plugin/AclOpsInterface.h"
#include "op_plugin/OpApiInterface.h"
#include "op_plugin/utils/op_api_common.h"
#include "op_plugin/utils/RandomUtil.h"
#include "torch_npu/csrc/framework/utils/RandomOpAdapter.h"

namespace op_api {
using npu_preparation = at_npu::native::OpPreparation;

at::Tensor rrelu_with_noise(
    const at::Tensor& self,
    const at::Tensor& noise,
    const at::Scalar& lower,
    const at::Scalar& upper,
    bool training,
    c10::optional<at::Generator> generator) {
  DO_COMPATIBILITY(aclnnRReluWithNoise, acl_op::rrelu_with_noise(self, noise, lower, upper, training, generator));
  at::Tensor result = npu_preparation::apply_tensor_without_format(self);
  const bool is_a5 = (c10_npu::GetSocVersion() >= c10_npu::SocVersion::Ascend950);
  // A5(Ascend950+) 对齐社区：空 tensor 提前返回，不消耗 generator offset；其他芯片保持原流程
  if (is_a5 && self.numel() == 0) {
    return result;
  }
  int64_t seed = 0;
  int64_t offset = 0;
  // A5(Ascend950+) 对齐社区：eval 模式不消耗随机数；其他芯片保持无条件取 seed/offset
  if (training || !is_a5) {
    auto gen_ =
        at::get_generator_or_default<at_npu::NPUGeneratorImpl>(generator, at_npu::detail::getDefaultNPUGenerator());
    // A5(Ascend950+) 对齐社区：offset 按 numel 动态计算；其他芯片保持固定 1<<28
    const uint64_t counter_offset = is_a5
        ? static_cast<uint64_t>(op_plugin::utils::calc_final_counter_offset(result))
        : (1ULL << 28);
    auto pair = gen_->philox_engine_inputs(counter_offset);
    seed = static_cast<int64_t>(pair.first);
    offset = static_cast<int64_t>(pair.second);
  }

  EXEC_NPU_CMD(aclnnRReluWithNoise, self, noise, lower, upper, training, seed, offset, result);

  return result;
}

at::Tensor& rrelu_with_noise_(
    at::Tensor& self,
    const at::Tensor& noise,
    const at::Scalar& lower,
    const at::Scalar& upper,
    bool training,
    c10::optional<at::Generator> generator) {
  const bool is_a5 = (c10_npu::GetSocVersion() >= c10_npu::SocVersion::Ascend950);
  // A5(Ascend950+) 对齐社区：空 tensor 提前返回，不消耗 generator offset；其他芯片保持原流程
  if (is_a5 && self.numel() == 0) {
    return self;
  }
  DO_COMPATIBILITY(
      aclnnInplaceRReluWithNoise, acl_op::rrelu_with_noise_(self, noise, lower, upper, training, generator));
  int64_t seed = 0;
  int64_t offset = 0;
  // A5(Ascend950+) 对齐社区：eval 模式不消耗随机数；其他芯片保持无条件取 seed/offset
  if (training || !is_a5) {
    auto gen_ =
        at::get_generator_or_default<at_npu::NPUGeneratorImpl>(generator, at_npu::detail::getDefaultNPUGenerator());
    // A5(Ascend950+) 对齐社区：offset 按 numel 动态计算；其他芯片保持固定 1<<28
    const uint64_t counter_offset = is_a5
        ? static_cast<uint64_t>(op_plugin::utils::calc_final_counter_offset(self))
        : (1ULL << 28);
    auto pair = gen_->philox_engine_inputs(counter_offset);
    seed = static_cast<int64_t>(pair.first);
    offset = static_cast<int64_t>(pair.second);
  }
  EXEC_NPU_CMD(aclnnInplaceRReluWithNoise, self, noise, lower, upper, training, seed, offset);

  return self;
}

at::Tensor& rrelu_with_noise_out(
    const at::Tensor& self,
    const at::Tensor& noise,
    const at::Scalar& lower,
    const at::Scalar& upper,
    bool training,
    c10::optional<at::Generator> generator,
    at::Tensor& output) {
  DO_COMPATIBILITY(
      aclnnRReluWithNoise, acl_op::rrelu_with_noise_out(self, noise, lower, upper, training, generator, output));
  npu_preparation::check_tensor({self, noise}, output, self);
  const bool is_a5 = (c10_npu::GetSocVersion() >= c10_npu::SocVersion::Ascend950);
  // A5(Ascend950+) 对齐社区：空 tensor 提前返回，不消耗 generator offset；其他芯片保持原流程
  if (is_a5 && self.numel() == 0) {
    return output;
  }
  int64_t seed = 0;
  int64_t offset = 0;
  // A5(Ascend950+) 对齐社区：eval 模式不消耗随机数；其他芯片保持无条件取 seed/offset
  if (training || !is_a5) {
    auto gen_ =
        at::get_generator_or_default<at_npu::NPUGeneratorImpl>(generator, at_npu::detail::getDefaultNPUGenerator());
    // A5(Ascend950+) 对齐社区：offset 按 numel 动态计算；其他芯片保持固定 1<<28
    const uint64_t counter_offset = is_a5
        ? static_cast<uint64_t>(op_plugin::utils::calc_final_counter_offset(output))
        : (1ULL << 28);
    auto pair = gen_->philox_engine_inputs(counter_offset);
    seed = static_cast<int64_t>(pair.first);
    offset = static_cast<int64_t>(pair.second);
  }
  EXEC_NPU_CMD(aclnnRReluWithNoise, self, noise, lower, upper, training, seed, offset, output);

  return output;
}

} // namespace op_api
