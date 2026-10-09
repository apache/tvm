/*
 * Licensed to the Apache Software Foundation (ASF) under one
 * or more contributor license agreements.  See the NOTICE file
 * distributed with this work for additional information
 * regarding copyright ownership. The ASF licenses this file
 * to you under the Apache License, Version 2.0 (the
 * "License"); you may not use this file except in compliance
 * with the License.  You may obtain a copy of the License at
 *
 *   http://www.apache.org/licenses/LICENSE-2.0
 *
 * Unless required by applicable law or agreed to in writing,
 * software distributed under the License is distributed on an
 * "AS IS" BASIS, WITHOUT WARRANTIES OR CONDITIONS OF ANY
 * KIND, either express or implied.  See the License for the
 * specific language governing permissions and limitations
 * under the License.
 */

/*!
 * \file lower_opaque_block.cc
 */

#include <tvm/ffi/cast.h>
#include <tvm/ffi/reflection/registry.h>
#include <tvm/ir/scope_stack.h>
#include <tvm/s_tir/stmt.h>
#include <tvm/s_tir/stmt_functor.h>
#include <tvm/s_tir/transform.h>
#include <tvm/tirx/op/memory.h>
#include <tvm/tirx/stmt.h>

#include <optional>

#include "ir_utils.h"

namespace tvm {
namespace s_tir {
using namespace tvm::prim;
using namespace tvm::tirx;

/*!
 * \brief Remove SBlock to ensure that the TIR can not be scheduled again.
 */
class OpaqueBlockLower : public StmtExprMutator {
 public:
  using StmtExprMutator::Mutate;
  using StmtExprMutator::Mutate_;

  static Stmt Rewrite(Stmt body) {
    auto lower = ffi::make_object<OpaqueBlockLower>();
    lower->storage_align_ = CollectStorageAlignAnnotation(body);
    return lower->Mutate(body, InplaceMode::kAllow).ValueOrUnchanged(std::move(body));
  }

 private:
  struct UnrollPolicy {
    std::optional<ffi::Any> auto_unroll_max_step;
    std::optional<ffi::Any> unroll_explicit;
  };

  UnchangedOr<Stmt> Mutate_(const SBlockRealizeNode* op, InplaceMode inplace_mode) final {
    // We have convert blocks into opaque blocks in previous passes.
    TVM_FFI_ICHECK(op->iter_values.empty())
        << "Non-opaque blocks are not allowed in FlattenBuffer. Please "
           "call pass ConvertBlocksToOpaque before.";
    // Block policy belongs to the loops inside the block after opaque lowering.
    auto parent_policy = unroll_policy_.Current();
    SBlock new_block = unroll_policy_.WithNewScope([&]() {
      unroll_policy_.Current() = parent_policy;
      UpdateUnrollPolicy(op->block->annotations);
      return this->Mutate(op->block, inplace_mode)
          .ValueOrUnchanged(op->block)
          .as_or_throw<SBlock>();
    });
    PrimExpr predicate = this->Mutate(op->predicate, inplace_mode).ValueOrUnchanged(op->predicate);
    // Step 2. Transform the `predicate` to if-then-else
    Stmt body = new_block->body;
    if (!IsOne(predicate)) {
      body = If(predicate, std::move(body));
    }
    // Step 3. Handle allocations in reverse order
    ffi::Map<Var, ffi::Array<PrimExpr>> addresses;
    if (auto value = new_block->annotations.Get(s_tir::attr::buffer_allocated_addr)) {
      for (const auto& entry : value.value().cast<BufferAllocatedAddresses>()) {
        addresses.Set(entry.get<0>(), entry.get<1>());
      }
    }
    for (size_t i = new_block->alloc_buffers.size(); i > 0; --i) {
      const TensorVar& buffer = new_block->alloc_buffers[i - 1];
      ffi::Map<ffi::String, ffi::Any> allocate_annotations;
      auto it = storage_align_.find(buffer.var());
      if (it != storage_align_.end()) {
        StorageAlignAnnotation allocate_aligns;
        for (auto tuple : it->second) {
          tuple.Set<0>(-1);
          allocate_aligns.push_back(tuple);
        }
        allocate_annotations.Set(tvm::s_tir::attr::kBufferDimAlign, allocate_aligns);
      }
      allocate_annotations.Set(tvm::tirx::attr::kBufferDataAlignment,
                               IntImm::Int32(buffer->data_alignment));
      ffi::Array<Expr> args{tvm::Tuple(buffer->shape), DataTypeImm(buffer->dtype->dtype),
                            StringImm(buffer.scope())};
      if (auto address = addresses.Get(buffer.var())) args.push_back(tvm::Tuple(address.value()));
      body = SeqStmt({Bind(buffer.var(), Call(buffer.type(), tirx::alloc_tensor_op(), args,
                                              DictAttrs(allocate_annotations))),
                      std::move(body)});
    }
    return body;
  }

  UnchangedOr<Stmt> Mutate_(const ForNode* op, InplaceMode inplace_mode) final {
    // Step 1. Update unit loop info.
    PrimExpr min = this->Mutate(op->min, inplace_mode).ValueOrUnchanged(op->min);
    PrimExpr extent = this->Mutate(op->extent, inplace_mode).ValueOrUnchanged(op->extent);
    auto step = this->Mutate(op->step, inplace_mode)
                    .as_or_throw<UnchangedOr<ffi::Optional<PrimExpr>>>()
                    .ValueOrUnchanged(op->step);
    auto previous_remap = VarRemapGet(op->loop_var);
    if (!tvm::tirx::GetThreadBinding(op).has_value() && IsOne(extent) && op->annotations.empty()) {
      // handling unit loop
      VarRemapSet(op->loop_var, prim::cast(op->loop_var.ty(), min));
    }

    // Keep policy on surviving descendants when this owner is lowered away.
    auto parent_policy = unroll_policy_.Current();
    ffi::Map<ffi::String, ffi::Any> new_annotations;
    auto annotations = op->annotations;
    Stmt body = unroll_policy_.WithNewScope([&]() {
      unroll_policy_.Current() = parent_policy;
      UpdateUnrollPolicy(op->annotations);
      const auto& policy = unroll_policy_.Current();
      if (policy.auto_unroll_max_step.has_value()) {
        annotations.Set(tvm::tirx::attr::kAutoUnrollMaxStep, policy.auto_unroll_max_step.value());
      }
      if (policy.unroll_explicit.has_value()) {
        annotations.Set(tvm::tirx::attr::kUnrollExplicit, policy.unroll_explicit.value());
      }
      // Rewrite annotations before visiting body-local definitions.
      new_annotations = HandleAnnotations(annotations);
      return this->Mutate(op->body, inplace_mode).ValueOrUnchanged(op->body);
    });
    VarRemapSet(op->loop_var, previous_remap);

    // Step 2. Keep thread-binding loops until LowerThreadBinding.
    if (!tvm::tirx::GetThreadBinding(op).has_value() && IsOne(extent) && op->annotations.empty() &&
        !op->annotations.count(tvm::s_tir::attr::kIrregularLoopMark)) {
      return body;
    }
    return For(op->loop_var, std::move(min), std::move(extent), op->kind, std::move(body),
               std::move(new_annotations), std::move(step), op->span);
  }

  void UpdateUnrollPolicy(const ffi::Map<ffi::String, ffi::Any>& annotations) {
    auto& policy = unroll_policy_.Current();
    if (auto value = annotations.Get(tvm::tirx::attr::kAutoUnrollMaxStep);
        value.has_value() && value.value() != nullptr) {
      policy.auto_unroll_max_step = value.value();
    }
    if (auto value = annotations.Get(tvm::tirx::attr::kUnrollExplicit);
        value.has_value() && value.value() != nullptr) {
      policy.unroll_explicit = value.value();
    }
  }

  // Effective policy is materialized on each surviving loop, preserving nested overrides.
  ScopeStack<UnrollPolicy> unroll_policy_;

  // Preserve loop annotations while remapping enclosing bindings. Null optional
  // policies do not override inherited values or reach code generation.
  ffi::Map<ffi::String, ffi::Any> HandleAnnotations(
      const ffi::Map<ffi::String, ffi::Any>& annotations) {
    ffi::Map<ffi::String, ffi::Any> preserved;
    for (const auto& [key, value] : annotations) {
      if ((key == tvm::tirx::attr::kAutoUnrollMaxStep || key == tvm::tirx::attr::kUnrollExplicit ||
           key == tvm::tirx::attr::kPragmaUnroll) &&
          value == nullptr) {
        continue;
      }
      preserved.Set(key, this->Mutate(value, InplaceMode::kDisallow).ValueOrUnchanged(value));
    }
    return preserved;
  }

  /*! \brief The map from buffer var to its storage alignment information. */
  std::unordered_map<Var, StorageAlignAnnotation> storage_align_;
};

namespace transform {

Pass LowerOpaqueBlock() {
  auto pass_func = [=](Function f, IRModule m, PassContext ctx) {
    if (!f->body.has_value()) return f;
    auto fptr = f.CopyOnWrite();
    fptr->body = OpaqueBlockLower::Rewrite(std::move(fptr->body).value());
    return f;
  };
  return CreateFunctionPass(pass_func, 0, "s_tir.LowerOpaqueBlock");
}

TVM_FFI_STATIC_INIT_BLOCK() {
  namespace refl = tvm::ffi::reflection;
  refl::GlobalDef().def("s_tir.transform.LowerOpaqueBlock", LowerOpaqueBlock);
}
}  // namespace transform

}  // namespace s_tir
}  // namespace tvm
