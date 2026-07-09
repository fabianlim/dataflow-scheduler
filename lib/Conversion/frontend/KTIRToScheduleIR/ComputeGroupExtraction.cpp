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
//
/// This pass identifies compute groups (sequences of operations between LoadOps
/// and StoreOps with the same access tile equivalence class) and extracts them
/// into separate functions in new modules.
///
/// Example transformation:
///
/// BEFORE:
/// -------
/// module {
///   func.func @main() {
///     scf.for %i = %c0 to %N step %c1 {
///       %tile1 = ktdp.construct_access_tile %A[%i, %c0]
///       %tile2 = ktdp.construct_access_tile %B[%i, %c0]
///       %tile3 = ktdp.construct_access_tile %C[%i, %c0]
///
///       %a = ktdp.load %tile1 : tensor<1x64xf16>
///       %b = ktdp.load %tile2 : tensor<1x64xf16>
///       %c_empty = tensor.empty() : tensor<1x64xf16>
///       %c = linalg.add ins(%a, %b : tensor<1x64xf16>, tensor<1x64xf16>)
///                       outs(%c_empty : tensor<1x64xf16>)
///       ktdp.store %c, %tile3
///     }
///   }
/// }
///
/// AFTER:
/// ------
/// module {
///   module {  // Original module
///     func.func @main() {
///       scf.for %i = %c0 to %N step %c1 {
///         func.call @local-schedule-0(%i) : (index) -> ()
///       }
///     }
///     func.func private @local-schedule-0(index)
///   }
///   module {  // Extracted function module
///     func.func private @local-schedule-0(%arg0: index) {
///       %tile1 = ktdp.construct_access_tile %A[%arg0, %c0]
///       %tile2 = ktdp.construct_access_tile %B[%arg0, %c0]
///       %tile3 = ktdp.construct_access_tile %C[%arg0, %c0]
///
///       %a = ktdp.load %tile1 : tensor<1x64xf16>
///       %b = ktdp.load %tile2 : tensor<1x64xf16>
///       %c_empty = tensor.empty() : tensor<1x64xf16>
///       %c = linalg.add ins(%a, %b : tensor<1x64xf16>, tensor<1x64xf16>)
///                       outs(%c_empty : tensor<1x64xf16>)
///       ktdp.store %c, %tile3
///       return
///     }
///   }
/// }
///
/// Key features:
/// - Identifies compute groups by access tile equivalence classes
/// - Extracts operations from first LoadOp to last StoreOp of each class
/// - Handles iter args (block arguments) by passing them as function parameters
/// - Recursively materializes dependencies (constants, memory views, etc.)
/// - Creates nested module structure with forward declarations
//
//===----------------------------------------------------------------------===//

#include "Ktdp/KtdpOps.hpp"
#include "dataflow-scheduler/Conversion/frontend/KTIRToScheduleIR/Passes.h"
#include "dataflow-scheduler/Dialect/KTDF/KTDF.h"
#include "dataflow-scheduler/Dialect/KTDFArch/KTDFArch.h"
#include "llvm/ADT/EquivalenceClasses.h"
#include "llvm/Support/Debug.h"
#include "mlir/Dialect/Arith/IR/Arith.h"
#include "mlir/Dialect/Func/IR/FuncOps.h"
#include "mlir/Dialect/Linalg/IR/Linalg.h"
#include "mlir/Dialect/Math/IR/Math.h"
#include "mlir/Dialect/SCF/IR/SCF.h"
#include "mlir/Dialect/Tensor/IR/Tensor.h"
#include "mlir/IR/BuiltinOps.h"
#include "mlir/IR/IRMapping.h"
#include "mlir/IR/PatternMatch.h"
#include "mlir/Pass/Pass.h"
#include "mlir/Transforms/RegionUtils.h"

#define PASS_NAME "compute-group-extraction"
#define DEBUG_TYPE PASS_NAME

using namespace scheduler;

namespace scheduler {
#define GEN_PASS_DEF_COMPUTEGROUPEXTRACTIONPASS
#include "dataflow-scheduler/Conversion/frontend/KTIRToScheduleIR/Passes.h.inc"
}  // namespace scheduler

namespace {
const char VerboseDebug[] = DEBUG_TYPE "-verbose";

static llvm::cl::opt<bool> DisableThisPass(
    "compute-group-extraction-disable",
    llvm::cl::desc("Disable Compute Group Extraction pass"),
    llvm::cl::init(false));

}  // unnamed namespace

namespace {
struct ComputeGroupExtractionPass
    : public impl::ComputeGroupExtractionPassBase<ComputeGroupExtractionPass> {
  void runOnOperation() final;

 private:
  /// A compute group is defined as the set of operations between
  /// first_load and last_store, in addition to any ancestor operations.
  struct ComputeGroup {
    mlir::Operation* first_load;
    mlir::Operation* last_store;
  };

  void runOn(mlir::ModuleOp module_op);

  /// Walks the ancestor tree of a StoreOp's data operand and unions access
  /// tiles from any LoadOps found with the StoreOp's access tile.
  /// @param store_op The StoreOp whose ancestors to walk
  /// @param access_tile_eq_classes Equivalence classes to update
  void unionAccessTilesFromAncestors(
      mlir::ktdp::StoreOp store_op,
      llvm::EquivalenceClasses<mlir::Value>& access_tile_eq_classes);

  /// Print equivalence classes for debugging.
  /// @param access_tile_eq_classes The equivalence classes to print
  void printEqClasses(
      llvm::EquivalenceClasses<mlir::Value>& access_tile_eq_classes);

  /// Verifiy that a compute operation has valid usage patterns.
  /// @param op The operation to verify
  /// @return true if the operation has valid uses, false otherwise
  bool verifyComputeOpUses(mlir::Operation* op);

  /// Build equivalence classes of access tiles by processing StoreOps in a
  /// block.
  /// @param block The block to process
  /// @param access_tile_eq_classes Equivalence classes to populate
  void buildAccessTileEqClasses(
      mlir::Block* block,
      llvm::EquivalenceClasses<mlir::Value>& access_tile_eq_classes);

  /// Extract a compute group into a new function in a child module.
  /// @param top_level_module The top-level module containing all child modules
  /// @param original_module The module containing the original function
  /// @param group The compute group to extract
  void extractComputeGroup(mlir::ModuleOp top_level_module,
                           mlir::ModuleOp original_module,
                           const ComputeGroup& group);

  /// Process a block to identify and collect compute groups for extraction.
  /// @param block The block to process
  /// @param access_tile_eq_classes Rquivalence classes of access tiles
  void processBlockForExtraction(
      mlir::Block* block,
      llvm::EquivalenceClasses<mlir::Value>& access_tile_eq_classes);

  /// Counter for generating unique function names
  int function_counter = 0;
  /// Collected compute groups
  llvm::SmallVector<ComputeGroup> groups_to_extract_;
};

void ComputeGroupExtractionPass::unionAccessTilesFromAncestors(
    mlir::ktdp::StoreOp store_op,
    llvm::EquivalenceClasses<mlir::Value>& access_tile_eq_classes) {
  mlir::Value store_access_tile = store_op.getAccessTile();
  mlir::Block* store_block = store_op->getBlock();

  llvm::SmallVector<mlir::Operation*> worklist = {store_op};
  llvm::DenseSet<mlir::Operation*> visited;

  // Starting at the store, walk all the ancestors, searching for loads
  // and union the store's access tile equivalence class with the class
  // of the load's access tile. This captures the dependencies between
  // loads and stores.
  while (!worklist.empty()) {
    mlir::Operation* current_op = worklist.back();
    worklist.pop_back();

    if (visited.count(current_op)) continue;
    visited.insert(current_op);

    if (auto load_op = mlir::dyn_cast<mlir::ktdp::LoadOp>(current_op)) {
      mlir::Value load_access_tile = load_op.getAccessTile();
      assert(load_op->getBlock() == store_block &&
             "LoadOp expected to be in same block as StoreOp");
      access_tile_eq_classes.unionSets(store_access_tile, load_access_tile);
      continue;
    }

    for (mlir::Value operand : current_op->getOperands()) {
      // Skip if operand is a basic block argument.
      if (mlir::isa<mlir::BlockArgument>(operand)) continue;

      mlir::Operation* operand_def_op = operand.getDefiningOp();
      worklist.push_back(operand_def_op);
    }
  }
}

bool ComputeGroupExtractionPass::verifyComputeOpUses(mlir::Operation* op) {
  bool has_store_use = false;
  bool has_compute_use = false;

  for (mlir::Value result : op->getResults()) {
    for (mlir::Operation* user : result.getUsers()) {
      if (mlir::isa<mlir::ktdp::StoreOp>(user)) {
        has_store_use = true;
      } else if (llvm::isa<mlir::linalg::LinalgDialect>(user->getDialect()) ||
                 llvm::isa<mlir::math::MathDialect>(user->getDialect()) ||
                 llvm::isa<mlir::arith::ArithDialect>(user->getDialect())) {
        has_compute_use = true;
      }
    }
  }

  if (has_store_use && has_compute_use) return false;

  return true;
}

void ComputeGroupExtractionPass::printEqClasses(
    llvm::EquivalenceClasses<mlir::Value>& access_tile_eq_classes) {
  for (llvm::EquivalenceClasses<mlir::Value>::iterator
           I = access_tile_eq_classes.begin(),
           E = access_tile_eq_classes.end();
       I != E; ++I) {
    if (!(*I)->isLeader()) continue;

    llvm::dbgs() << "  Class leader: " << (*I)->getData() << "\n";
    llvm::dbgs() << "    Members:\n";

    for (llvm::EquivalenceClasses<mlir::Value>::member_iterator MI =
             access_tile_eq_classes.member_begin(**I);
         MI != access_tile_eq_classes.member_end(); ++MI) {
      llvm::dbgs() << "    " << *MI << "\n";
    }
    llvm::dbgs() << "\n-------- END OF CLASS MEMBERS -------\n";
  }
}

void ComputeGroupExtractionPass::buildAccessTileEqClasses(
    mlir::Block* block,
    llvm::EquivalenceClasses<mlir::Value>& access_tile_eq_classes) {
  for (mlir::Operation& block_op : block->getOperations()) {
    if (auto store_op = mlir::dyn_cast<mlir::ktdp::StoreOp>(&block_op)) {
      // For every store in block, union its access tile's class with the
      // classes of the access tiles of its ancestor loads.
      access_tile_eq_classes.insert(store_op.getAccessTile());
      unionAccessTilesFromAncestors(store_op, access_tile_eq_classes);
    } else if (llvm::isa<mlir::linalg::LinalgDialect>(block_op.getDialect()) ||
               llvm::isa<mlir::math::MathDialect>(block_op.getDialect()) ||
               llvm::isa<mlir::arith::ArithDialect>(block_op.getDialect())) {
      assert(verifyComputeOpUses(&block_op) &&
             "Compute operation must have valid usage pattern");
    }
  }
}

// Helper function to recursively collect iter args from operand dependencies
static void collectArgsUsed(mlir::Value val,
                            llvm::DenseSet<mlir::Operation*>& visited,
                            llvm::SmallVectorImpl<mlir::Value>& args) {
  // If this is a block argument (e.g., iter arg from scf.for), add it to the
  // list of arguments to pass to the extracted function
  if (mlir::isa<mlir::BlockArgument>(val)) {
    // Avoid duplicates
    if (llvm::find(args, val) == args.end()) {
      args.push_back(val);
    }
    return;
  }

  mlir::Operation* op = val.getDefiningOp();

  // Avoid revisiting operations
  if (visited.count(op)) return;
  visited.insert(op);

  // Recursively collect from operands
  for (mlir::Value operand : op->getOperands()) {
    collectArgsUsed(operand, visited, args);
  }
}

// Helper function to recursively materialize dependencies
static void materializeDependency(mlir::Value val, mlir::IRMapping& mapper,
                                  mlir::OpBuilder& builder) {
  // If we already cloned this ancestor, we're done
  if (mapper.contains(val)) return;

  // If this is a block argument, it should already be mapped
  if (mlir::isa<mlir::BlockArgument>(val)) {
    assert(mapper.contains(val) && "Block argument should be mapped");
    return;
  }

  mlir::Operation* op = val.getDefiningOp();

  // Ensure all operands of the ancestor are cloned first
  for (mlir::Value operand : op->getOperands()) {
    materializeDependency(operand, mapper, builder);
  }

  // Now clone the ancestor itself into the new block
  builder.clone(*op, mapper);
}

// A loop nest is a reduction compute group when it contains both a ktdp.load
// and a ktdp.store that live in *different* blocks of the nest — the per-block
// straight-line scan pairs a load with a store only within one block, so it
// cannot capture this shape (loads in the reduction loop body, store in the
// outer output-partition loop body). Such a nest is extracted wholesale as its
// outermost loop.
static bool loopNestBracketsCrossBlockLoadStore(mlir::scf::ForOp for_op) {
  mlir::ktdp::LoadOp a_load;
  mlir::ktdp::StoreOp a_store;
  for_op.walk([&](mlir::Operation* op) {
    if (auto l = mlir::dyn_cast<mlir::ktdp::LoadOp>(op)) a_load = l;
    if (auto s = mlir::dyn_cast<mlir::ktdp::StoreOp>(op)) a_store = s;
  });
  if (!a_load || !a_store) return false;
  return a_load->getBlock() != a_store->getBlock();
}

void ComputeGroupExtractionPass::extractComputeGroup(
    mlir::ModuleOp top_level_module, mlir::ModuleOp original_module,
    const ComputeGroup& group) {
  assert(group.first_load && group.last_store);

  std::string func_name =
      "local-schedule-" + std::to_string(function_counter++);

  mlir::OpBuilder builder(top_level_module);

  // Get the original function to copy its attributes
  auto original_func = group.first_load->getParentOfType<mlir::func::FuncOp>();
  assert(original_func && "Compute group must be inside a function");

  // Collect operations to move (from first_load to last_store inclusive)
  llvm::SmallVector<mlir::Operation*> ops_to_move;
  bool collecting = false;
  mlir::Block* group_block = group.first_load->getBlock();
  for (mlir::Operation& op : group_block->getOperations()) {
    if (&op == group.first_load) {
      collecting = true;
    }
    if (collecting) {
      ops_to_move.push_back(&op);
    }
    if (&op == group.last_store) {
      break;
    }
  }

  // Values used by the range but defined outside it: each op's operands, plus
  // the free variables of any nested regions (so a whole loop nest extracted as
  // one op pulls in the memory views / constants its body references).
  llvm::SmallVector<mlir::Value> external_values;
  for (mlir::Operation* op : ops_to_move) {
    for (mlir::Value operand : op->getOperands()) {
      external_values.push_back(operand);
    }
    for (mlir::Region& region : op->getRegions()) {
      llvm::SetVector<mlir::Value> free_vals;
      mlir::getUsedValuesDefinedAbove(region, free_vals);
      for (mlir::Value v : free_vals) external_values.push_back(v);
    }
  }

  // Collect args (block arguments) needed by the extracted function
  llvm::SmallVector<mlir::Value> args;
  llvm::DenseSet<mlir::Operation*> visited;
  for (mlir::Value ext : external_values) {
    collectArgsUsed(ext, visited, args);
  }

  // Build function type with args as parameters
  llvm::SmallVector<mlir::Type> arg_types;
  for (mlir::Value arg : args) {
    arg_types.push_back(arg.getType());
  }
  auto func_type = builder.getFunctionType(arg_types, {});

  // Create forward declaration in the original module
  builder.setInsertionPointToEnd(original_module.getBody());
  auto forward_decl = mlir::func::FuncOp::create(top_level_module.getLoc(),
                                                 func_name, func_type);
  forward_decl.setPrivate();
  builder.insert(forward_decl);

  // Create a new child module in the top-level module for this extracted
  // function
  builder.setInsertionPointToEnd(top_level_module.getBody());
  auto extracted_module =
      mlir::ModuleOp::create(builder, top_level_module.getLoc());

  // Create the function definition in the extracted module
  builder.setInsertionPointToStart(extracted_module.getBody());
  auto func_op = mlir::func::FuncOp::create(top_level_module.getLoc(),
                                            func_name, func_type);
  func_op.setPrivate();
  // Copy grid attribute from original function if it exists
  if (auto grid_attr = original_func->getAttr("grid")) {
    func_op->setAttr("grid", grid_attr);
  }
  extracted_module.push_back(func_op);

  // Create a dummy function that calls the extracted function to prevent
  // Symbol DCE from removing it (since it's private and called from another
  // module)
  builder.setInsertionPointToEnd(extracted_module.getBody());
  auto dummy_func_name = func_name + "_keep_alive";
  auto dummy_func = mlir::func::FuncOp::create(top_level_module.getLoc(),
                                               dummy_func_name, func_type);
  dummy_func.setPrivate();
  extracted_module.push_back(dummy_func);

  mlir::Block* dummy_block = dummy_func.addEntryBlock();
  builder.setInsertionPointToStart(dummy_block);

  // Create dummy arguments for the call
  llvm::SmallVector<mlir::Value> dummy_args;
  for (size_t i = 0; i < args.size(); ++i) {
    dummy_args.push_back(dummy_block->getArgument(i));
  }

  // Add call to the extracted function
  mlir::func::CallOp::create(builder, top_level_module.getLoc(), func_op,
                             dummy_args);
  mlir::func::ReturnOp::create(builder, top_level_module.getLoc());

  // Create entry block with arguments
  mlir::Block* func_block = func_op.addEntryBlock();
  builder.setInsertionPointToStart(func_block);

  // Map args to function arguments so they can be used when cloning
  mlir::IRMapping mapper;
  for (size_t i = 0; i < args.size(); ++i) {
    mapper.map(args[i], func_block->getArgument(i));
  }

  // Step 1: Materialize all dependencies for the entire range.
  // (e.g. arith.constants, construct_memory_views, construct_access_tiles),
  // including the free variables of nested regions collected above.
  for (mlir::Value ext : external_values) {
    materializeDependency(ext, mapper, builder);
  }

  // Step 2: Clone the actual range
  for (mlir::Operation* op : ops_to_move) {
    // Skip if already cloned as dependency
    bool already_cloned = false;
    for (mlir::Value result : op->getResults()) {
      if (mapper.contains(result)) {
        already_cloned = true;
        break;
      }
    }

    if (!already_cloned) {
      builder.clone(*op, mapper);
    }
  }

  // Create call operation before erasing operations
  builder.setInsertionPoint(group.first_load);
  auto call_op = mlir::func::CallOp::create(builder, top_level_module.getLoc(),
                                            forward_decl, args);
  // Step 3: Erase the original operations in reverse order to avoid dangling
  // uses
  for (auto it = ops_to_move.rbegin(); it != ops_to_move.rend(); ++it) {
    mlir::Operation* op = *it;
    assert(op->use_empty() && "Operation should have no uses left");
    op->erase();
  }

  // Add return operation to the new function
  builder.setInsertionPointToEnd(func_block);
  mlir::func::ReturnOp::create(builder, top_level_module.getLoc());

  LLVM_DEBUG({
    llvm::dbgs() << "Extracted compute group into function: " << func_name
                 << "\n";
    llvm::dbgs() << "Operations: " << ops_to_move.size() << "\n";
    llvm::dbgs() << "Block arguments: " << args.size() << "\n";
  });
}

void ComputeGroupExtractionPass::processBlockForExtraction(
    mlir::Block* block,
    llvm::EquivalenceClasses<mlir::Value>& access_tile_eq_classes) {
  // Keep track of visited equivalence classes of access tiles for the current
  // block to assert they are not visited multiple times.
  llvm::DenseSet<mlir::Value> visited_class_leaders;
  mlir::Value current_class_leader = nullptr;
  bool last_mem_op_was_load = false;
  mlir::Operation* first_load_op = nullptr;
  mlir::Operation* last_store_op = nullptr;

  // Traverse operations in the block, extracting each compute group. Boundaries
  // are determined by changes in current equivalence class of load/store access
  // tiles and/or control flow operations.
  for (mlir::Operation& block_op : block->getOperations()) {
    // Check for control flow operations - they terminate the current compute
    // group.
    // Reason: Otherwise, if control flow operations were to be extracted,
    // we might end up with nested func calls.
    if (block_op.getNumRegions() > 0) {
      // Save current compute group if any
      if (current_class_leader && first_load_op && last_store_op) {
        groups_to_extract_.push_back({first_load_op, last_store_op});

        // Mark current class as visited
        visited_class_leaders.insert(current_class_leader);

        // Reset tracking
        current_class_leader = nullptr;
        first_load_op = nullptr;
        last_store_op = nullptr;
        last_mem_op_was_load = false;
      }
      continue;
    }

    if (auto load_op = mlir::dyn_cast<mlir::ktdp::LoadOp>(&block_op)) {
      mlir::Value load_access_tile = load_op.getAccessTile();
      assert(access_tile_eq_classes.findLeader(load_access_tile) !=
                 access_tile_eq_classes.member_end() &&
             "expecting access_tile to have equivalence class");
      mlir::Value load_class_leader =
          access_tile_eq_classes.getLeaderValue(load_access_tile);
      assert(visited_class_leaders.find(load_class_leader) ==
                 visited_class_leaders.end() &&
             "Equivalence class visited twice");

      // If this is a different class than current, save previous group and
      // switch
      if (current_class_leader && current_class_leader != load_class_leader) {
        assert(!last_mem_op_was_load &&
               "found consecutive loads in different equivalence classes");

        // Save the previous compute group
        if (first_load_op && last_store_op) {
          groups_to_extract_.push_back({first_load_op, last_store_op});
        }

        // Mark previous class as visited before switching
        visited_class_leaders.insert(current_class_leader);

        current_class_leader = load_class_leader;
        first_load_op = nullptr;
        last_store_op = nullptr;
      } else if (!current_class_leader) {
        // First load - initialize current class
        current_class_leader = load_class_leader;
      }

      // Track first load of current class
      if (!first_load_op) {
        first_load_op = &block_op;
      }

      last_mem_op_was_load = true;
    } else if (auto store_op = mlir::dyn_cast<mlir::ktdp::StoreOp>(&block_op)) {
      mlir::Value store_access_tile = store_op.getAccessTile();

      assert(access_tile_eq_classes.findLeader(store_access_tile) !=
                 access_tile_eq_classes.member_end() &&
             "expecting access_tile to have equivalence class");

      mlir::Value store_class_leader =
          access_tile_eq_classes.getLeaderValue(store_access_tile);

      assert(current_class_leader && "StoreOp found before any LoadOp");

      assert(current_class_leader == store_class_leader &&
             "StoreOp must belong to the same class as previous LoadOp");

      // Track last store of current class
      last_store_op = &block_op;
      last_mem_op_was_load = false;
    }
  }

  // Save the last compute group
  if (first_load_op && last_store_op) {
    groups_to_extract_.push_back({first_load_op, last_store_op});
  }
}

void ComputeGroupExtractionPass::runOn(mlir::ModuleOp module_op) {
  // First pass: detect loop-nest reduction compute groups. Their loads and
  // store span different blocks of the nest (loads in the reduction loop body,
  // store in the outer output-partition loop body), so the per-block scan below
  // cannot pair them; extract the outermost bracketing loop wholesale.
  llvm::SmallPtrSet<mlir::Operation*, 4> loop_nest_roots;
  module_op.walk([&](mlir::func::FuncOp func) {
    for (mlir::Block& body_block : func.getBody()) {
      for (mlir::Operation& op : body_block) {
        auto for_op = mlir::dyn_cast<mlir::scf::ForOp>(&op);
        if (for_op && loopNestBracketsCrossBlockLoadStore(for_op)) {
          groups_to_extract_.push_back({for_op, for_op});
          loop_nest_roots.insert(for_op);
        }
      }
    }
  });

  // Walk all blocks and collect (straight-line) compute groups to extract.
  module_op.walk([&](mlir::Block* block) {
    // Skip blocks that live inside an already-claimed loop-nest group.
    for (mlir::Operation* root : loop_nest_roots) {
      if (root->isAncestor(block->getParentOp())) {
        return mlir::WalkResult::advance();
      }
    }

    llvm::EquivalenceClasses<mlir::Value> access_tile_eq_classes;

    buildAccessTileEqClasses(block, access_tile_eq_classes);

    if (access_tile_eq_classes.empty()) {
      return mlir::WalkResult::advance();
    }

    LLVM_DEBUG({
      llvm::dbgs() << "Access tile equivalence classes:\n";
      printEqClasses(access_tile_eq_classes);
    });

    // Process block to collect compute groups
    processBlockForExtraction(block, access_tile_eq_classes);

    return mlir::WalkResult::advance();
  });

  // If no groups to extract, nothing to do
  if (groups_to_extract_.empty()) {
    return;
  }

  // Move original content to a child module and create child
  // modules for extracted functions. New structure:
  // module {
  //   module { // original
  //     func.func @orig {
  //       <original ops with extracted code replaced by func call>
  //     }
  //   }
  //   module { // extracted module #1
  //     ...
  //   }
  //   ... // other extracted modules
  // }
  mlir::OpBuilder builder(module_op);

  // Create a child module for the original content
  builder.setInsertionPointToStart(module_op.getBody());
  auto original_module = mlir::ModuleOp::create(builder, module_op.getLoc());

  // Move all operations from the original module to the new child module,
  // EXCEPT ktdf_arch.device declarations, which must stay as direct children of
  // the top-level module: device-dependent passes run once on the top module
  // and resolve the device via DeviceManager (which only sees devices directly
  // nested in the module it is built on), then walk into the nested modules to
  // do their work. Moving the device into a nested module hides it from those
  // passes.
  auto& original_ops = module_op.getBody()->getOperations();
  auto& child_ops = original_module.getBody()->getOperations();
  for (mlir::Operation& op : llvm::make_early_inc_range(llvm::make_range(
           std::next(original_module->getIterator()), original_ops.end()))) {
    if (mlir::isa<mlir::ktdf_arch::DeviceOp>(op)) continue;
    op.moveBefore(original_module.getBody(), child_ops.end());
  }

  // Now extract all collected compute groups, each into its own child module
  for (const auto& group : groups_to_extract_) {
    extractComputeGroup(module_op, original_module, group);
  }

  // Clean up side-effect-free ops left dead after extraction (e.g. ops that
  // were cloned into child modules but whose originals are now unused in the
  // top-level module). runRegionDCE recurses into nested regions, so passing
  // the module's regions covers child modules created above.
  mlir::IRRewriter rewriter(module_op.getContext());
  (void)mlir::runRegionDCE(rewriter, module_op->getRegions());
}

void ComputeGroupExtractionPass::runOnOperation() {
  if (DisableThisPass) return;
  LLVM_DEBUG(llvm::dbgs() << "Compute Group Extraction Pass\n");
  mlir::ModuleOp module_op = getOperation();
  runOn(module_op);
}

}  // namespace

std::unique_ptr<mlir::Pass> scheduler::createComputeGroupExtractionPass() {
  return std::make_unique<ComputeGroupExtractionPass>();
}
