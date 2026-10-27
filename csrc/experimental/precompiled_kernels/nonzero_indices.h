/*
 * Copyright 2026 Google LLC
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

#ifndef TORCH_TPU_CSRC_EXPERIMENTAL_PRECOMPILED_KERNELS_NONZERO_INDICES_H_
#define TORCH_TPU_CSRC_EXPERIMENTAL_PRECOMPILED_KERNELS_NONZERO_INDICES_H_

#include <memory>

#include "absl/status/statusor.h"
#include "csrc/common/cache_key.h"
#include "csrc/common/compilation.h"
#include "csrc/common/compilation_spec.h"
#include "xla/pjrt/pjrt_client.h"
#include "xla/pjrt/pjrt_executable.h"

namespace torch_tpu {

// Identifies a precompiled nonzero indices kernel. The value is used as the
// `id_key` of the kernel's `CompilationCacheKey`, which is persisted in the
// names of the tier-2 cache entries, so values must be explicit, non-negative,
// and must never be reused or renumbered. -1 is reserved for keys that don't
// identify a dynamic kernel.
enum class NonzeroKernelId : int {
  // The nonzero indices kernel for F32[M,N] inputs.
  kNonzero2D = 1,
};

// Builds and compiles the Mosaic nonzero kernel. Run through `Execute` with the
// F32[M,N] input and the logical output shape S64[K,2], the executable returns
// the (row, column) coordinates of the input's nonzero elements, ordered by
// row, then column. The predicate excludes only +0.0 and -0.0, matching
// torch.nonzero.
//
// Buffer contract (all payloads have no dynamic-metadata prefix):
// - Input: F32[M,N]{1,0:T(8,128)}, the only buffer the caller supplies.
// - Output: S64[K,2]{0,1:T(2,128)}. `Execute` allocates the destination itself
//   as the S32[R,128]{1,0:T(1,128)} view the Mosaic kernel was compiled against
//   (R = 4 * ceil(K/128); rows [0, R/2) hold interleaved row/col low words,
//   [R/2, R) hold zeroed high words), donates it, and bitcasts the result back
//   to S64[K,2]. The detour exists only because Mosaic does not support S64
//   memrefs; callers never see it.
//   NB: requires K > 2 because the XLA default layout for S64[K,2] switches to
//   {1,0:T(2,128)} when K <= 2.
//
// Caller-checked arithmetic bounds: 1 <= M <= INT32_MAX,
// 1 <= N <= INT32_MAX - 127, and 3 <= K <= min(M*N, INT32_MAX).
absl::StatusOr<std::unique_ptr<xla::PjRtLoadedExecutable>>
BuildNonzeroIndicesExecutable(xla::PjRtClient& client,
                              UniqueCompileOptions compile_options);

// Returns the UnboundedDynamicExecutionMetadata for the nonzero indices
// kernel.
UnboundedDynamicExecutionMetadata MakeNonzeroDynamicMetadata();

// Returns the ShapelessKey a nonzero graph
// would be lowered to.
ShapelessKey NonZeroCacheKey();

}  // namespace torch_tpu

#endif  // TORCH_TPU_CSRC_EXPERIMENTAL_PRECOMPILED_KERNELS_NONZERO_INDICES_H_
