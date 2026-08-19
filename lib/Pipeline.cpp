//===-- Pipeline.cpp --------------------------------------------*- c++ -*-===//
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
//
// This file implements the scheduler pipeline registration.
//
//===----------------------------------------------------------------------===//

#include "dataflow-scheduler/Pipeline.h"

#include <mlir/Pass/PassManager.h>
#include <mlir/Transforms/Passes.h>

#include "dataflow-scheduler/Conversion/backend/ScheduleIRToDFIR/Passes.h"
#include "dataflow-scheduler/Conversion/frontend/KTIRToScheduleIR/Passes.h"
#include "dataflow-scheduler/Dialect/KTDF/Transforms/Passes.h"
#include "dataflow-scheduler/Dialect/KTDFArch/Transforms/Passes.h"
#include "dataflow-scheduler/Transforms/Passes.h"
#include "dataflow-scheduler/Utils/SchedulerExtContext.h"
#include "llvm/Support/CommandLine.h"

namespace {

// MLIR's canonicalizer + LICM. Safe on KTIR/KTDF, NOT safe on input that is already DFIR:
// agen.composite_load has no results and no declared memory effects, so dead-op elimination
// deletes it together with the dataflow.send in its region, and the matching receive then
// waits forever on hardware. Only a driver feeding an existing DFIR through the pipeline
// needs this off.
static llvm::cl::opt<bool> DisableCleanupPasses(
    "disable-pipeline-cleanup-passes",
    llvm::cl::desc("Disable the pipeline's generic canonicalize/LICM cleanup passes. For "
                   "driving already-lowered DFIR through the pipeline; a normal KTIR run "
                   "wants them on"),
    llvm::cl::init(false));

/// Adds one of those cleanup passes, unless they are switched off.
void addCleanupPass(mlir::OpPassManager& pm, std::unique_ptr<mlir::Pass> pass) {
  if (DisableCleanupPasses) return;
  pm.addPass(std::move(pass));
}

}  // unnamed namespace

using namespace scheduler;

void scheduler::buildKTIRFrontendPipeline(
    mlir::OpPassManager& pm, const SchedulerExtContext& scheduler_ctx) {
  pm.addPass(createKTIRLegalityCheckPass());
  pm.addPass(createComputeGroupExtractionPass());
  pm.addPass(createConstructThreeStagePipelinePass(scheduler_ctx));
}

void scheduler::buildSchedulerOptimizationPipeline(
    mlir::OpPassManager& pm, const SchedulerExtContext& scheduler_ctx) {
  // TODO: Check state / CLI arguments to determine which pattern groups to
  //       enable. E.g., device variants, relaxed numerics, ...
  pm.addPass(mlir::ktdf_arch::createApplyPatternsPass());
  pm.addPass(createPathExpansionPass(scheduler_ctx));
  pm.addPass(createScalarBroadcastLegalizationPass());
  pm.addPass(createNormalizeSCFForLoopsPass());
  // Canonicalize to get rid of intervening code and single iteration loops
  addCleanupPass(pm, mlir::createCanonicalizerPass());
  pm.addPass(createTileSCFForLoopsPass());
  // Canonicalize to simplify tiling arith ops
  // (probably not needed for custom tiling regime)
  addCleanupPass(pm, mlir::createCanonicalizerPass());
  addCleanupPass(pm, mlir::createLoopInvariantCodeMotionPass());
  pm.addPass(mlir::ktdf::createStageCoarseningPass());
  // Must precede ReductionLoopExposure: it is what removes the innermost
  // (register-lane) dimension from the reduction set, so that pass only ever
  // materialises loop-axis reductions.
  pm.addPass(mlir::ktdf::createReductionLaneCollapsePass());
  pm.addPass(mlir::ktdf::createReductionLoopExposurePass());
  pm.addPass(mlir::ktdf::createMapReductionPartialsPass());
  pm.addPass(mlir::ktdf::createBroadcastPromotionPass());
  pm.addPass(createDoubleBufferingPass(scheduler_ctx));
  // Parallelizing before tile selection is beneficial because the tile size
  // selection pass would now take parallel instances into account while
  // determining tile sizes.
  pm.addPass(createParallelizeLoopsAcrossInstancesPass(scheduler_ctx));
  pm.addPass(mlir::ktdf::createTileSizeSelectionPass());
  addCleanupPass(pm, mlir::createCanonicalizerPass());
  pm.addPass(createAffineMinCanonicalizationPass());
  pm.addPass(mlir::ktdf::createSubsumeLinearizeIndexPass());
  pm.addPass(createAddressAssignmentPass(scheduler_ctx));
  // TODO: position of cross-instance parallelization is TBD
  // pm.addPass(createParallelizeLoopsAcrossInstancesPass(scheduler_ctx));
  pm.addPass(createNormalizeGridTo1DPass());
}

void scheduler::buildDFIRBackendPipeline(
    mlir::OpPassManager& pm, const SchedulerExtContext& scheduler_ctx) {
  pm.addPass(createKTDFToKTDFLoweringPass(scheduler_ctx));
  pm.addPass(createKTDFLowToDFIRPass());
}

void scheduler::buildKTDPToDFIRPipeline(
    mlir::OpPassManager& pm, const SchedulerExtContext& scheduler_ctx) {
  buildKTIRFrontendPipeline(pm, scheduler_ctx);
  buildSchedulerOptimizationPipeline(pm, scheduler_ctx);
  buildDFIRBackendPipeline(pm, scheduler_ctx);
}
