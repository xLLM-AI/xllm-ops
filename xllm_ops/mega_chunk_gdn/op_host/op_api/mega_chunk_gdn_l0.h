/* Copyright 2026 The xLLM Authors. All Rights Reserved.

Licensed under the Apache License, Version 2.0 (the "License");
you may not use this file except in compliance with the License.
You may obtain a copy of the License at

    https://github.com/jd-opensource/xllm/blob/main/LICENSE

Unless required by applicable law or agreed to in writing, software
distributed under the License is distributed on an "AS IS" BASIS,
WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
See the License for the specific language governing permissions and
limitations under the License.
==============================================================================*/

#pragma once

#include <tuple>

#include "opdev/make_op_executor.h"
#include "opdev/op_executor.h"

namespace l0op {
std::tuple<const aclTensor *, const aclTensor *, const aclTensor *, const aclTensor *, const aclTensor *,
           const aclTensor *, const aclTensor *, const aclTensor *, const aclTensor *, const aclTensor *,
           const aclTensor *, const aclTensor *>
MegaChunkGdn(const aclTensor *q, const aclTensor *k, const aclTensor *v, const aclTensor *g, const aclTensor *beta,
             const aclTensor *maskLower, const aclTensor *maskFull, const aclTensor *minusIdentity,
             const aclTensor *cuSeqlens, const aclTensor *initialState, int64_t numMatrices, bool hasInitialState,
             const aclTensor *out, const aclTensor *gSum, const aclTensor *gT, const aclTensor *betaT,
             const aclTensor *a, const aclTensor *aInvF32, const aclTensor *aInv, const aclTensor *w,
             const aclTensor *u, const aclTensor *h, const aclTensor *vNew, const aclTensor *finalState,
             aclOpExecutor *executor);
}  // namespace l0op
