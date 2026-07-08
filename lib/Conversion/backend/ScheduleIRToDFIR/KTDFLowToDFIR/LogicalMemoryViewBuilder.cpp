//===----------------------------------------------------------------------===//
//
// Part of the Dataflow Scheduler project.
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
//
//===----------------------------------------------------------------------===//

#include "dataflow-scheduler/Conversion/backend/ScheduleIRToDFIR/KTDFLowToDFIR/LogicalMemoryViewBuilder.h"

#include "Ktdp/KtdpOps.hpp"
#include "dataflow-scheduler/Analysis/ArchViews/MemoryTree.h"
#include "dataflow-scheduler/Conversion/backend/ScheduleIRToDFIR/KTDFToKTDFLow/UniformInfra.h"
#include "dataflow-scheduler/Conversion/backend/ScheduleIRToDFIR/KTDFToKTDFLow/UnitMaterializer.h"
#include "dataflow-scheduler/Dialect/Dataflow/Dataflow.h"
#include "dataflow-scheduler/Dialect/KTDF/KTDF.h"
#include "dataflow-scheduler/Dialect/KTDFArch/Analysis/DeviceManager.h"
#include "dataflow-scheduler/Conversion/backend/ScheduleIRToDFIR/KTDFLowToDFIR/Utils.h"
#include "dataflow-scheduler/Transforms/Utils/Utils.h"
#include "llvm/ADT/DenseMap.h"
#include "llvm/ADT/SetVector.h"
#include "llvm/Support/Debug.h"
#include "mlir/Dialect/Arith/IR/Arith.h"
#include "mlir/Dialect/Bufferization/IR/Bufferization.h"
#include "mlir/Dialect/MemRef/IR/MemRef.h"
#include "mlir/IR/AffineMap.h"
#include "mlir/IR/Builders.h"
#include "mlir/IR/BuiltinOps.h"
#include "mlir/IR/Value.h"
#include "mlir/Pass/AnalysisManager.h"

#define DEBUG_TYPE "logical-memory-view-builder"

using namespace scheduler;

namespace {

/// Returns the memory space attribute from a memref type's memory space
/// encoding, or std::nullopt if the type has no memory space attribute.
std::optional<mlir::Attribute> getMemorySpaceAttr(mlir::Type type) {
  auto memref = mlir::dyn_cast<mlir::MemRefType>(type);
  if (!memref) return std::nullopt;
  auto space_attr = memref.getMemorySpace();
  if (!space_attr) return std::nullopt;
  return space_attr;
}

/// Returns true if the only uses of `val` are memref.dealloc ops.
bool onlyDeallocUses(mlir::Value val) {
  return llvm::all_of(val.getUsers(), [](mlir::Operation* user) {
    return mlir::isa<mlir::memref::DeallocOp>(user);
  });
}

/// Phase 1: Walk all program_unit bodies in `func`.
/// - Collect memory space attributes used by Source A chains and Source B
/// casts.
/// - Prune Source B casts whose only uses are memref.dealloc (delete cast +
/// deallocs). Returns the set of needed memory space attributes.
llvm::SetVector<ResourceType> discoverAndPrune(mlir::func::FuncOp func) {
  llvm::SetVector<ResourceType> needed;

  func.walk([&](mlir::dataflow::ProgramUnitOp pu) {
    llvm::SmallVector<mlir::Operation*> to_prune;

    pu.getRegion().front().walk([&](mlir::Operation* op) {
      // Source A: ktdp.construct_memory_view — get memory space from the
      // downstream memory_space_cast result type.
      if (auto cmv = mlir::dyn_cast<mlir::ktdp::ConstructMemoryViewOp>(op)) {
        for (mlir::Operation* user : cmv.getResult().getUsers()) {
          if (auto msc =
                  mlir::dyn_cast<mlir::memref::MemorySpaceCastOp>(user)) {
            if (auto ms = getMemorySpaceAttr(msc.getDest().getType()))
              needed.insert(*ms);
          }
        }
        return;
      }

      // Source B: unrealized_conversion_cast index -> memref<..., memory_space>
      if (auto ucc = mlir::dyn_cast<mlir::UnrealizedConversionCastOp>(op)) {
        if (ucc.getInputs().size() != 1 ||
            !mlir::isa<mlir::IndexType>(ucc.getInputs()[0].getType()))
          return;
        if (ucc.getOutputs().size() != 1) return;
        auto ms = getMemorySpaceAttr(ucc.getOutputs()[0].getType());
        if (!ms) return;

        if (onlyDeallocUses(ucc.getOutputs()[0])) {
          to_prune.push_back(op);
        } else {
          needed.insert(*ms);
        }
      }
    });

    // Prune: delete deallocs then the cast.
    for (mlir::Operation* op : to_prune) {
      auto ucc = mlir::cast<mlir::UnrealizedConversionCastOp>(op);
      llvm::SmallVector<mlir::Operation*> deallocs(
          ucc.getOutputs()[0].getUsers().begin(),
          ucc.getOutputs()[0].getUsers().end());
      for (mlir::Operation* d : deallocs) d->erase();
      op->erase();
      LLVM_DEBUG(llvm::dbgs() << "  Pruned dealloc-only cast\n");
    }
  });

  return needed;
}

/// Phase 3a: resolve from_unit for each needed memory space inside a
/// program_unit. Global spaces (DDR) are looked up directly from
/// memory_unit_ssa. Per-core spaces (L1) get a uniform map + query emitted
/// inside the body. Compute-local spaces (lrfreg) use get_local_unit on the
/// PU's instance arg (%arg0).
mlir::LogicalResult buildResolvedUnits(
    mlir::dataflow::ProgramUnitOp pu,
    const llvm::SetVector<ResourceType>& needed_spaces,
    const MemoryUnitSSAMap& memory_unit_ssa,
    const scheduler::arch_view::MemoryTree& memory_tree,
    const SchedulerExtContext& ext_ctx,
    llvm::DenseMap<ResourceType, mlir::Value>& resolved_units,
    mlir::OpBuilder& builder) {
  llvm::SetVector<ResourceType> per_core;
  for (auto ms : needed_spaces) {
    if (isComputeLocalMemorySpace(ms)) {
      // Compute-local: resolve "lrfreg" -> dataflow.get_local_unit %arg0
      // {name="lrfreg"}. The PU instance arg is %arg0 (the first block arg of
      // the PU region). The builder is already positioned at the PU body start.
      mlir::Value inst = pu.getRegion().front().getArgument(0);
      auto lu = mlir::dataflow::GetLocalUnitOp::create(
          builder, pu.getLoc(), builder.getIndexType(), inst,
          builder.getStringAttr("lrfreg"));
      resolved_units[ms] = lu.getResult();
    } else if (memory_tree.isGlobalMemory(ms)) {
      auto it = memory_unit_ssa.find({ms, -1});
      if (it == memory_unit_ssa.end())
        return pu.emitError("global memory unit SSA not found");
      resolved_units[ms] = it->second;
    } else if (memory_tree.isPerCoreScratchPadMemory(ms)) {
      per_core.insert(ms);
    }
  }

  if (per_core.empty()) return mlir::success();

  UniformInfra infra(pu->getParentOfType<mlir::func::FuncOp>());
  return infra.buildMemoryUniformMaps(pu, per_core, memory_unit_ssa, ext_ctx,
                                      resolved_units, builder);
}

/// Build a 1-D linearization affine map from static strides.
/// E.g., strides [4096, 4096, 64, 1] → (d0,d1,d2,d3) -> (d0*4096 + d1*4096 +
/// d2*64 + d3)
mlir::AffineMap buildLinearizationMap(mlir::MLIRContext* ctx,
                                      llvm::ArrayRef<int64_t> strides) {
  unsigned rank = strides.size();
  mlir::AffineExpr sum = mlir::getAffineConstantExpr(0, ctx);
  for (unsigned i = 0; i < rank; ++i) {
    sum = sum + mlir::getAffineDimExpr(i, ctx) *
                    mlir::getAffineConstantExpr(strides[i], ctx);
  }
  return mlir::AffineMap::get(rank, 0, sum, ctx);
}

/// Build an N-D tile get_logical_memory_view.
/// start_address = cmv.getOffset() + reinterpret_offset (always).
/// The layout uses the N-D linearization map from the memref strides.
/// §3 (ADDRESSING_DESIGN_V2): offset is always loop-invariant, so there is one
/// unified view builder. buildInvariantBaseView and buildTileAddressView are
/// merged into this single function.
static mlir::dataflow::GetLogicalMemoryViewOp buildTileAddressView(
    mlir::OpBuilder& builder, mlir::Location loc,
    mlir::MemRefType src_type, mlir::Value from_unit,
    mlir::Value start_address, mlir::AffineMap layout_map) {
  auto plain_type =
      mlir::MemRefType::get(src_type.getShape(), src_type.getElementType());
  return mlir::dataflow::GetLogicalMemoryViewOp::create(
      builder, loc, plain_type, from_unit, start_address,
      mlir::AffineMapAttr::get(layout_map));
}

/// Phase 3b: replace Source A chains with get_logical_memory_view.
/// Emits the view op and RAUWs the memref.cast result inline; does not
/// populate `replacements` (Source A handles its own erasure).
/// §3 (ADDRESSING_DESIGN_V2): always computes start_address = cmv.getOffset()
/// + reinterpret_offset; uses a single unified N-D tile-address view builder.
mlir::LogicalResult replaceSourceAChains(
    mlir::dataflow::ProgramUnitOp pu,
    const llvm::DenseMap<ResourceType, mlir::Value>& resolved_units,
    llvm::DenseMap<mlir::Value, mlir::Value>& replacements,
    mlir::OpBuilder& builder) {
  auto* ctx = pu.getContext();

  llvm::SmallVector<mlir::ktdp::ConstructMemoryViewOp> chains;
  pu.getRegion().front().walk(
      [&](mlir::ktdp::ConstructMemoryViewOp cmv) { chains.push_back(cmv); });

  for (auto cmv : chains) {
    // Find memory_space_cast user.
    mlir::memref::MemorySpaceCastOp msc;
    for (auto* user : cmv.getResult().getUsers()) {
      msc = mlir::dyn_cast<mlir::memref::MemorySpaceCastOp>(user);
      if (msc) break;
    }
    if (!msc)
      return cmv.emitError(
          "construct_memory_view: expected memory_space_cast user");

    // Find reinterpret_cast user.
    mlir::memref::ReinterpretCastOp rc;
    for (auto* user : msc.getDest().getUsers()) {
      rc = mlir::dyn_cast<mlir::memref::ReinterpretCastOp>(user);
      if (rc) break;
    }
    if (!rc)
      return msc.emitError("memory_space_cast: expected reinterpret_cast user");

    // Find memref.cast user (optional - may not exist).
    mlir::memref::CastOp mc;
    for (auto* user : rc.getResult().getUsers()) {
      mc = mlir::dyn_cast<mlir::memref::CastOp>(user);
      if (mc) break;
    }

    // Validate static sizes.
    for (int64_t s : cmv.getStaticSizes()) {
      if (mlir::ShapedType::isDynamic(s))
        return cmv.emitError(
            "construct_memory_view: dynamic sizes not supported");
    }

    // Validate static strides.
    auto static_strides = cmv.getStaticStrides();
    for (int64_t s : static_strides) {
      if (mlir::ShapedType::isDynamic(s))
        return cmv.emitError(
            "construct_memory_view: dynamic strides not supported");
    }

    // Build layout map from static strides.
    auto layout_map = buildLinearizationMap(ctx, static_strides);

    // §3 (ADDRESSING_DESIGN_V2): the reinterpret_cast offset is always
    // loop-invariant (loop IVs were excluded at pass-02 time). Always compute
    // start_address = cmv.getOffset() + reinterpret_offset and use the single
    // tile-address view builder. No has_invariant_base split needed.
    mlir::Value start_address = cmv.getOffset();
    builder.setInsertionPointAfter(rc);
    {
      mlir::OpFoldResult reinterpret_offset = rc.getConstifiedMixedOffset();
      if (auto offset_attr =
              llvm::dyn_cast<mlir::Attribute>(reinterpret_offset)) {
        int64_t reinterpret_offset_val =
            llvm::cast<mlir::IntegerAttr>(offset_attr).getInt();
        if (reinterpret_offset_val != 0) {
          mlir::Value offset_cst = mlir::arith::ConstantIndexOp::create(
              builder, cmv.getLoc(), reinterpret_offset_val);
          start_address = mlir::arith::AddIOp::create(builder, cmv.getLoc(),
                                                      start_address, offset_cst);
        }
      } else {
        auto offset_val = llvm::cast<mlir::Value>(reinterpret_offset);
        start_address = mlir::arith::AddIOp::create(builder, cmv.getLoc(),
                                                    start_address, offset_val);
      }
    }

    // Get from_unit.
    auto ms = getMemorySpaceAttr(msc.getDest().getType());
    if (!ms) return msc.emitError("memory_space_cast: no memory space");
    auto it = resolved_units.find(*ms);
    if (it == resolved_units.end())
      return cmv.emitError("no resolved unit for memory space");
    mlir::Value from_unit = it->second;

    // Emit get_logical_memory_view using the unified tile-address view builder.
    auto src_type = mlir::cast<mlir::MemRefType>(rc.getResult().getType());
    auto view_op = buildTileAddressView(builder, cmv.getLoc(), src_type,
                                        from_unit, start_address, layout_map);

    // Replace all uses of the old chain tail with the new view.
    // The tail is either memref.cast (if present) or reinterpret_cast.
    if (mc) {
      mc.getDest().replaceAllUsesWith(view_op.getData());
      mc.erase();
    } else {
      rc.getResult().replaceAllUsesWith(view_op.getData());
    }

    // Erase the now-dead chain: reinterpret_cast, memory_space_cast,
    // construct_memory_view.
    rc.erase();
    msc.erase();
    cmv.erase();
  }
  return mlir::success();
}

/// Phase 3c: replace Source B unrealized_conversion_casts with
/// get_logical_memory_view. Dealloc-only casts were pruned in Phase 1.
mlir::LogicalResult replaceSourceBCasts(
    mlir::dataflow::ProgramUnitOp pu,
    const llvm::DenseMap<ResourceType, mlir::Value>& resolved_units,
    llvm::DenseMap<mlir::Value, mlir::Value>& replacements,
    mlir::OpBuilder& builder) {
  auto* ctx = pu.getContext();

  llvm::SmallVector<mlir::UnrealizedConversionCastOp> casts;
  pu.getRegion().front().walk([&](mlir::UnrealizedConversionCastOp ucc) {
    if (ucc.getInputs().size() != 1 ||
        !mlir::isa<mlir::IndexType>(ucc.getInputs()[0].getType()))
      return;
    if (ucc.getOutputs().size() != 1) return;
    if (!getMemorySpaceAttr(ucc.getOutputs()[0].getType())) return;
    casts.push_back(ucc);
  });

  for (auto ucc : casts) {
    auto result_type =
        mlir::cast<mlir::MemRefType>(ucc.getOutputs()[0].getType());
    auto shape = result_type.getShape();

    // Assert fully static shape.
    for (int64_t dim : shape) {
      if (mlir::ShapedType::isDynamic(dim))
        return ucc.emitError(
            "unrealized_conversion_cast: dynamic shape not supported");
    }

    // Synthesize contiguous row-major strides from shape.
    llvm::SmallVector<int64_t> strides(shape.size());
    strides.back() = 1;
    for (int i = static_cast<int>(shape.size()) - 2; i >= 0; --i)
      strides[i] = strides[i + 1] * shape[i + 1];
    auto layout_map = buildLinearizationMap(ctx, strides);

    // Get from_unit.
    auto ms = getMemorySpaceAttr(result_type);
    if (!ms)
      return ucc.emitError("unrealized_conversion_cast: no ktdf memory space");
    auto it = resolved_units.find(*ms);
    if (it == resolved_units.end())
      return ucc.emitError("no resolved unit for memory space");
    mlir::Value from_unit = it->second;

    mlir::Value addr = ucc.getInputs()[0];
    auto plain_type =
        mlir::MemRefType::get(shape, result_type.getElementType());

    builder.setInsertionPoint(ucc);
    auto view_op = mlir::dataflow::GetLogicalMemoryViewOp::create(
        builder, ucc.getLoc(), plain_type, from_unit, addr,
        mlir::AffineMapAttr::get(layout_map));

    // Delete remaining dealloc users (mixed-use casts that survived Phase 1).
    llvm::SmallVector<mlir::Operation*> deallocs;
    for (auto* user : ucc.getOutputs()[0].getUsers())
      if (mlir::isa<mlir::memref::DeallocOp>(user)) deallocs.push_back(user);
    for (auto* d : deallocs) d->erase();

    // If the ucc result flows through a memref.cast (e.g., dynamizing dims for
    // select_memref), RAUW the cast's result with the view now and erase the
    // cast so that propagateTypes only ever sees data_transfer/select_memref
    // as consumers of ucc_result. Also update select_memref result types whose
    // operand type changed.
    mlir::Value ucc_result = ucc.getOutputs()[0];
    for (auto* user : llvm::make_early_inc_range(ucc_result.getUsers())) {
      if (auto mc = mlir::dyn_cast<mlir::memref::CastOp>(user)) {
        // Update select_memref result types before RAUW so we can still find
        // them via mc.getDest() users.
        for (auto* mc_user : mc.getDest().getUsers()) {
          if (auto sel = mlir::dyn_cast<mlir::ktdf::SelectMemrefOp>(mc_user))
            sel.getResult().setType(
                mlir::cast<mlir::MemRefType>(view_op.getData().getType()));
        }
        mc.getDest().replaceAllUsesWith(view_op.getData());
        mc.erase();
        break;
      }
    }
    replacements[ucc_result] = view_op.getData();
  }
  return mlir::success();
}

/// Phase 3d: RAUW old values with new get_logical_memory_view results and
/// propagate plain-memref types through select_memref and data_transfer.
/// Also handles bufferization.to_tensor and
/// bufferization.materialize_in_destination consumers (the lrfreg accumulator
/// RMW ops emitted by pass 02) — those are lowered to agen.vector_load/store
/// in runOperationLowerings (the operation lowering step).
mlir::LogicalResult propagateTypes(
    mlir::dataflow::ProgramUnitOp pu,
    const llvm::DenseMap<mlir::Value, mlir::Value>& replacements) {
  for (auto& [old_val, new_val] : replacements) {
    llvm::SmallVector<mlir::Operation*> users(old_val.getUsers().begin(),
                                              old_val.getUsers().end());
    for (auto* user : users) {
      if (auto dt = mlir::dyn_cast<mlir::ktdf::DataTransferOp>(user)) {
        dt->replaceUsesOfWith(old_val, new_val);
      } else if (auto sel = mlir::dyn_cast<mlir::ktdf::SelectMemrefOp>(user)) {
        sel->replaceUsesOfWith(old_val, new_val);
        // All operands of select_memref have the same element type; use the
        // new value's plain type for the result.
        sel.getResult().setType(
            mlir::cast<mlir::MemRefType>(new_val.getType()));
        for (auto* sel_user : sel.getResult().getUsers()) {
          if (!mlir::isa<mlir::ktdf::DataTransferOp>(sel_user))
            return sel.emitError(
                "select_memref result used by unexpected op; expected "
                "data_transfer");
        }
      } else if (mlir::isa<mlir::bufferization::ToTensorOp,
                            mlir::bufferization::MaterializeInDestinationOp>(
                     user)) {
        // Accumulator RMW ops: update the memref operand to the plain view.
        // These are lowered to agen.vector_load/store in runOperationLowerings
        // before canonicalizeFunc runs.
        user->replaceUsesOfWith(old_val, new_val);
      } else {
        return pu.emitError(
            "unexpected consumer of memory view; expected "
            "data_transfer or select_memref");
      }
    }
  }
  return mlir::success();
}

}  // namespace

mlir::LogicalResult scheduler::buildLogicalMemoryViews(
    mlir::func::FuncOp func,
    const scheduler::arch_view::MemoryTree& memory_tree,
    const SchedulerExtContext& ext_ctx) {
  LLVM_DEBUG(llvm::dbgs() << "buildLogicalMemoryViews on " << func.getName()
                          << "\n");

  // Phase 1: discover needed memory spaces and prune dealloc-only casts.
  auto needed_spaces = discoverAndPrune(func);
  if (needed_spaces.empty()) {
    LLVM_DEBUG(llvm::dbgs() << "  No memory spaces found; skipping\n");
    return mlir::success();
  }

  // Phase 2: extract grid size, then materialize memory-space get_unit ops
  // at func-entry (after existing compute get_unit ops).
  int grid_size = 0;
  if (mlir::failed(extractGridSize(func, grid_size))) return mlir::failure();

  // Find insertion point: after last GetUnitOp in entry block, or at block
  // start if none exist.
  mlir::Block& entry = func.getBody().front();
  mlir::OpBuilder builder(func.getContext());
  mlir::Operation* last_get_unit = nullptr;
  for (mlir::Operation& op : entry) {
    if (mlir::isa<mlir::dataflow::GetUnitOp>(op)) last_get_unit = &op;
  }
  if (last_get_unit)
    builder.setInsertionPointAfter(last_get_unit);
  else
    builder.setInsertionPointToStart(&entry);

  // Filter out compute-local spaces (lrfreg) before calling
  // materializeMemoryUnits — those are resolved per program_unit via
  // get_local_unit (in buildResolvedUnits), not by a global get_unit.
  llvm::SetVector<ResourceType> materializable_spaces;
  for (auto ms : needed_spaces) {
    if (!isComputeLocalMemorySpace(ms)) materializable_spaces.insert(ms);
  }

  UnitMaterializer materializer(func);
  MemoryUnitSSAMap memory_unit_ssa;
  if (!materializable_spaces.empty() &&
      mlir::failed(materializer.materializeMemoryUnits(
          materializable_spaces, grid_size, memory_tree, memory_unit_ssa,
          builder)))
    return mlir::failure();

  // Phase 3: per-program_unit rewrites.
  llvm::SmallVector<mlir::dataflow::ProgramUnitOp> program_units;
  func.walk([&](mlir::dataflow::ProgramUnitOp pu) {
    program_units.push_back(pu);
    return mlir::WalkResult::skip();
  });

  for (auto pu : program_units) {
    mlir::Block& pu_body = pu.getRegion().front();
    builder.setInsertionPointToStart(&pu_body);

    // Phase 3a: build resolved_units map (uniform maps for per-core, direct
    // lookup for global).
    llvm::DenseMap<ResourceType, mlir::Value> resolved_units;
    if (mlir::failed(buildResolvedUnits(pu, needed_spaces, memory_unit_ssa,
                                        memory_tree, ext_ctx, resolved_units,
                                        builder)))
      return mlir::failure();

    llvm::DenseMap<mlir::Value, mlir::Value> replacements;

    // Phase 3b: Source A chains.
    if (mlir::failed(
        replaceSourceAChains(pu, resolved_units, replacements, builder)))
      return mlir::failure();

    // Phase 3c: Source B casts.
    if (mlir::failed(
            replaceSourceBCasts(pu, resolved_units, replacements, builder)))
      return mlir::failure();

    // Phase 3d: RAUW + type propagation.
    if (mlir::failed(propagateTypes(pu, replacements))) return mlir::failure();

    // Erase original Source A chain ops and Source B casts (now dead).
    for (auto& [old_val, new_val] : replacements) {
      if (old_val.use_empty()) old_val.getDefiningOp()->erase();
    }
    (void)pu_body;
  }

  return mlir::success();
}
