#include "vector.h"

#include <detail/fusion.h>

#include <stdexcept>

#include "logger.h"
#include "perfetto/trace.h"
#include "vector_desc.h"

#ifndef DPURT
#define DPURT
#include <dpu>  // UPMEM rt syslib
#define CHECK_UPMEM(x) DPU_ASSERT(x)
#endif

namespace detail {
VectorDesc::~VectorDesc() {
  auto& runtime = DpuRuntime::get();
  // The runtime owns the logger and the allocator, and shutdown() destroys
  // both.  A descriptor outliving it has nothing left to report to and no MRAM
  // to give back -- the DPU set is already freed -- so there is nothing to do.
  // This is the normal case for a garbage-collected binding, where finalizers
  // run after atexit.
  if (!runtime.is_initialized()) return;

  if (vector_id != 0) {
#if ENABLE_DPU_LOGGING >= 1
    Logger& logger = runtime.get_logger();
    log_deallocation(logger, type_name, num_elements, vector_id,
                     allocated_footprint_bytes, !needs_layout_materialization,
                     (debug_name ? debug_name : ""), debug_file, debug_line);
#endif
  }
  if (ptr_allocated) {
    runtime.get_allocator().deallocate_upmem_vector(this);
  }
}

template <typename T>
bool all_identical(const T* arr, size_t n) {
  for (size_t i = 1; i < n; i++) {
    if (std::memcmp(&arr[0], &arr[i], sizeof(T)) != 0) return false;
  }
  return true;
}

void vec_xfer_to_dpu(char* cpu, VectorDescRef desc) {
  auto& runtime = DpuRuntime::get();
  runtime.get_allocator().realize_allocation(desc);
  dpu_set_t& dpu_set = runtime.dpu_set();
  dpu_set_t dpu;

  uint32_t idx_dpu = 0;
  size_t element = 0;

  DPU_FOREACH(dpu_set, dpu, idx_dpu) {
    CHECK_UPMEM(dpu_prepare_xfer(dpu, &(cpu[element])));
    element += desc->desc[idx_dpu].size_bytes - desc->reserved_bytes;
  }

  uint32_t mram_location = desc->desc[0].ptr;
  size_t xfer_size = desc->desc[0].allocated_bytes - desc->reserved_bytes;
  trace::scoped_event trace_scoped("transfer", "vec_xfer_to_dpu");
  CHECK_UPMEM(dpu_push_xfer(dpu_set, DPU_XFER_TO_DPU,
                            DPU_MRAM_HEAP_POINTER_NAME, mram_location,
                            xfer_size, DPU_XFER_ASYNC));
}

// Reads every shard into `cpu` at a uniform `stride`.  The caller must have
// sized `cpu` for stride * num_dpus, since one transfer size applies to the
// whole DPU set; see ShardLayout.
void vec_xfer_from_dpu_strided(char* cpu, VectorDescRef desc, size_t stride) {
  auto& runtime = DpuRuntime::get();
  runtime.get_allocator().realize_allocation(desc);
  dpu_set_t& dpu_set = runtime.dpu_set();
  dpu_set_t dpu;

  uint32_t idx_dpu = 0;
  DPU_FOREACH(dpu_set, dpu, idx_dpu) {
    CHECK_UPMEM(dpu_prepare_xfer(dpu, &(cpu[(size_t)idx_dpu * stride])));
  }

  trace::scoped_event trace_scoped("transfer", "vec_xfer_from_dpu");
  CHECK_UPMEM(dpu_push_xfer(dpu_set, DPU_XFER_FROM_DPU,
                            DPU_MRAM_HEAP_POINTER_NAME, desc->desc[0].ptr,
                            stride, DPU_XFER_ASYNC));
}

void internal_launch_binary_scalar(VectorDescRef res, VectorDescRef lhs,
                                   uint32_t scalar, KernelID kernel_id) {
  auto& runtime = DpuRuntime::get();
  runtime.get_allocator().realize_allocation(res);
  runtime.get_allocator().realize_allocation(lhs);

  uint32_t nr_of_dpus = runtime.num_dpus();
  DPU_LAUNCH_ARGS args[nr_of_dpus] = {};

  for (uint32_t i = 0; i < nr_of_dpus; i++) {
    args[i].kernel = static_cast<uint32_t>(kernel_id);
    args[i].ktype = static_cast<uint8_t>(KERNEL_BINARY_SCALAR);
    args[i].num_elements = lhs->desc[i].size_bytes / lhs->element_size;
    args[i].size_type = lhs->element_size;
    args[i].binary_scalar.lhs_offset = (lhs->desc[i].ptr);
    args[i].binary_scalar.rhs_scalar = scalar;
    args[i].binary_scalar.res_offset = (res->desc[i].ptr);
  }

#if ENABLE_DPU_LOGGING >= 1
  Logger& logger = DpuRuntime::get().get_logger();
  log_dpu_launch_args(logger, args, nr_of_dpus);
#endif

  dpu_set_t& dpu_set = runtime.dpu_set();
  dpu_set_t dpu;
  uint32_t idx_dpu = 0;

  if (all_identical(args, nr_of_dpus)) {
    CHECK_UPMEM(dpu_broadcast_to(dpu_set, "args", 0, &args[0], sizeof(args[0]),
                                 DPU_XFER_DEFAULT));
  } else {
    DPU_FOREACH(dpu_set, dpu, idx_dpu) {
      CHECK_UPMEM(dpu_prepare_xfer(dpu, &args[idx_dpu]));
    }
    CHECK_UPMEM(dpu_push_xfer(dpu_set, DPU_XFER_TO_DPU, "args", 0,
                              sizeof(args[0]), DPU_XFER_DEFAULT));
  }
  CHECK_UPMEM(dpu_launch(dpu_set, DPU_ASYNCHRONOUS));
}

void internal_launch_binary(VectorDescRef res, VectorDescRef lhs,
                            VectorDescRef rhs, KernelID kernel_id) {
  auto& runtime = DpuRuntime::get();
  runtime.get_allocator().realize_allocation(res);
  runtime.get_allocator().realize_allocation(lhs);
  runtime.get_allocator().realize_allocation(rhs);

  uint32_t nr_of_dpus = runtime.num_dpus();
  DPU_LAUNCH_ARGS args[nr_of_dpus];

  for (uint32_t i = 0; i < nr_of_dpus; i++) {
    args[i].kernel = static_cast<uint32_t>(kernel_id);
    args[i].ktype = static_cast<uint8_t>(KERNEL_BINARY);
    args[i].num_elements = rhs->desc[i].size_bytes / rhs->element_size;
    args[i].size_type = rhs->element_size;
    args[i].binary.lhs_offset = (lhs->desc[i].ptr);
    args[i].binary.rhs_offset = (rhs->desc[i].ptr);
    args[i].binary.res_offset = (res->desc[i].ptr);
  }

#if ENABLE_DPU_LOGGING >= 1
  Logger& logger = DpuRuntime::get().get_logger();
  log_dpu_launch_args(logger, args, nr_of_dpus);
#endif

  dpu_set_t& dpu_set = runtime.dpu_set();
  dpu_set_t dpu;
  uint32_t idx_dpu = 0;

  if (all_identical(args, nr_of_dpus)) {
    CHECK_UPMEM(dpu_broadcast_to(dpu_set, "args", 0, &args[0], sizeof(args[0]),
                                 DPU_XFER_DEFAULT));
  } else {
    DPU_FOREACH(dpu_set, dpu, idx_dpu) {
      CHECK_UPMEM(dpu_prepare_xfer(dpu, &args[idx_dpu]));
    }
    CHECK_UPMEM(dpu_push_xfer(dpu_set, DPU_XFER_TO_DPU, "args", 0,
                              sizeof(args[0]), DPU_XFER_DEFAULT));
  }
  CHECK_UPMEM(dpu_launch(dpu_set, DPU_ASYNCHRONOUS));
}

void internal_launch_unary(VectorDescRef res, VectorDescRef rhs,
                           KernelID kernel_id) {
  auto& runtime = DpuRuntime::get();
  runtime.get_allocator().realize_allocation(res);
  runtime.get_allocator().realize_allocation(rhs);

  uint32_t nr_of_dpus = runtime.num_dpus();
  DPU_LAUNCH_ARGS args[nr_of_dpus];

  for (uint32_t i = 0; i < nr_of_dpus; i++) {
    args[i].kernel = static_cast<uint32_t>(kernel_id);
    args[i].ktype = static_cast<uint8_t>(KERNEL_PIPELINE);
    args[i].num_elements = rhs->desc[i].size_bytes / rhs->element_size;
    args[i].size_type = rhs->element_size;
    args[i].unary.rhs_offset = (rhs->desc[i].ptr);
    args[i].unary.res_offset = (res->desc[i].ptr);
  }

#if ENABLE_DPU_LOGGING >= 1
  Logger& logger = DpuRuntime::get().get_logger();
  log_dpu_launch_args(logger, args, nr_of_dpus);
#endif

  dpu_set_t& dpu_set = runtime.dpu_set();
  dpu_set_t dpu;
  uint32_t idx_dpu = 0;

  if (all_identical(args, nr_of_dpus)) {
    CHECK_UPMEM(dpu_broadcast_to(dpu_set, "args", 0, &args[0], sizeof(args[0]),
                                 DPU_XFER_DEFAULT));
  } else {
    DPU_FOREACH(dpu_set, dpu, idx_dpu) {
      CHECK_UPMEM(dpu_prepare_xfer(dpu, &args[idx_dpu]));
    }
    CHECK_UPMEM(dpu_push_xfer(dpu_set, DPU_XFER_TO_DPU, "args", 0,
                              sizeof(args[0]), DPU_XFER_DEFAULT));
  }
  CHECK_UPMEM(dpu_launch(dpu_set, DPU_ASYNCHRONOUS));
}

void internal_launch_reduction(VectorDescRef res, VectorDescRef rhs,
                               KernelID kernel_id) {
  auto& runtime = DpuRuntime::get();
  runtime.get_allocator().realize_allocation(res);
  runtime.get_allocator().realize_allocation(rhs);

  uint32_t nr_of_dpus = runtime.num_dpus();
  DPU_LAUNCH_ARGS args[nr_of_dpus];

  for (uint32_t i = 0; i < nr_of_dpus; i++) {
    args[i].kernel = static_cast<uint32_t>(kernel_id);
    args[i].ktype = static_cast<uint8_t>(KERNEL_REDUCTION);
    args[i].num_elements = rhs->desc[i].size_bytes / rhs->element_size;
    args[i].size_type = rhs->element_size;
    args[i].reduction.rhs_offset = (rhs->desc[i].ptr);
    args[i].reduction.res_offset = (res->desc[i].ptr);
  }

#if ENABLE_DPU_LOGGING >= 1
  Logger& logger = DpuRuntime::get().get_logger();
  log_dpu_launch_args(logger, args, nr_of_dpus);
#endif

  dpu_set_t& dpu_set = runtime.dpu_set();
  dpu_set_t dpu;
  uint32_t idx_dpu = 0;

  if (all_identical(args, nr_of_dpus)) {
    CHECK_UPMEM(dpu_broadcast_to(dpu_set, "args", 0, &args[0], sizeof(args[0]),
                                 DPU_XFER_DEFAULT));
  } else {
    DPU_FOREACH(dpu_set, dpu, idx_dpu) {
      CHECK_UPMEM(dpu_prepare_xfer(dpu, &args[idx_dpu]));
    }
    CHECK_UPMEM(dpu_push_xfer(dpu_set, DPU_XFER_TO_DPU, "args", 0,
                              sizeof(args[0]), DPU_XFER_DEFAULT));
  }
  CHECK_UPMEM(dpu_launch(dpu_set, DPU_ASYNCHRONOUS));
}

#if PIPELINE
void internal_launch_universal_pipeline(
    VectorDescRef res, VectorDescRef init, const std::vector<uint8_t>& ops,
    const std::vector<VectorDescRef>& operands, KernelID kernel_id,
    const std::vector<uint32_t>& scalars,
    const std::vector<uint32_t>& extra_scalars,
    const std::vector<VectorDescRef>& extra_outputs,
    std::string_view kernel_hash) {
  auto& runtime = DpuRuntime::get();
  if (res) runtime.get_allocator().realize_allocation(res);
  if (init) runtime.get_allocator().realize_allocation(init);
  for (auto& op : operands) {
    if (op) runtime.get_allocator().realize_allocation(op);
  }
  for (auto& out : extra_outputs) {
    if (out) runtime.get_allocator().realize_allocation(out);
  }
  uint32_t nr_of_dpus = runtime.num_dpus();
  DPU_LAUNCH_ARGS args[nr_of_dpus];

  // Accumulated, not i * stride: shard sizes can be ragged.
  uint32_t index_base = 0;

  for (uint32_t i = 0; i < nr_of_dpus; i++) {
    args[i].kernel = static_cast<uint32_t>(kernel_id);
    args[i].ktype = static_cast<uint8_t>(KERNEL_UNARY);

    args[i].num_elements =
        init ? (init->desc[i].size_bytes / init->element_size) : 0;
    args[i].size_type =
        init ? init->element_size : (res ? res->element_size : 4);

    args[i].pipeline.init_offset = init ? init->desc[i].ptr : 0;
    args[i].pipeline.res_offset = res ? res->desc[i].ptr : 0;
    args[i].pipeline.index_base = index_base;
    index_base += args[i].num_elements;

    for (size_t j = 0; j < MAX_HFUSE_CHAINS; ++j) {
      if (j < extra_outputs.size()) {
        args[i].pipeline.extra_res_offsets[j] = extra_outputs[j]->desc[i].ptr;
        args[i].pipeline.local_sizes[j] = extra_outputs[j]->num_elements;
        args[i].pipeline.local_reduce_ops[j] =
            extra_outputs[j]->local_reduce_opcode;
      } else {
        args[i].pipeline.extra_res_offsets[j] = 0;
        args[i].pipeline.local_sizes[j] = 0;
        args[i].pipeline.local_reduce_ops[j] = OP_SUM;
      }
    }

#if !JIT
    // The interpreter reads args.pipeline.ops, which is MAX_VFUSE_OPS long.
    // Truncating here would silently drop the tail of the program, so fail
    // loudly instead -- every path that builds an RPN is supposed to bound it.
    if (ops.size() > MAX_VFUSE_OPS)
      throw std::runtime_error("RPN program of " + std::to_string(ops.size()) +
                               " opcodes exceeds MAX_VFUSE_OPS (" +
                               std::to_string(MAX_VFUSE_OPS) +
                               "); rebuild with JIT=1 or raise MAX_VFUSE_OPS");
#endif
    args[i].pipeline.num_ops =
        std::min((size_t)ops.size(), (size_t)MAX_VFUSE_OPS);

    for (size_t j = 0; j < args[i].pipeline.num_ops; ++j) {
      args[i].pipeline.ops[j] = ops[j];
    }

    // Map operands by index (0..MAX_VFUSE_INPUTS-1)
    for (size_t j = 0; j < MAX_VFUSE_INPUTS; ++j) {
      if (j < operands.size()) {
        args[i].pipeline.binary_operands[j] = operands[j]->desc[i].ptr;
      } else {
        args[i].pipeline.binary_operands[j] = 0;
      }
    }

    // Map scalar arguments
    for (size_t j = 0; j < MAX_PIPELINE_SCALARS; ++j) {
      if (j < scalars.size()) {
        args[i].pipeline.scalars[j] = scalars[j];
      } else {
        args[i].pipeline.scalars[j] = 0;
      }
    }

    // Map extra JIT scalars
    for (size_t j = 0; j < 8; ++j) {
      if (j < extra_scalars.size()) {
        args[i].pipeline.extra_scalars[j] = extra_scalars[j];
      } else {
        args[i].pipeline.extra_scalars[j] = 0;
      }
    }
  }

#if ENABLE_DPU_LOGGING >= 1
  Logger& logger = DpuRuntime::get().get_logger();
  detail::FusionRpnSummary rpn_summary = detail::summarize_fusion_rpn(ops);
  log_dpu_launch_args(logger, args, nr_of_dpus, rpn_summary.decoded_ops,
                      rpn_summary.chains, kernel_hash);
#endif

  dpu_set_t& dpu_set = runtime.dpu_set();
  dpu_set_t dpu;
  uint32_t idx_dpu = 0;

  if (all_identical(args, nr_of_dpus)) {
    CHECK_UPMEM(dpu_broadcast_to(dpu_set, "args", 0, &args[0], sizeof(args[0]),
                                 DPU_XFER_DEFAULT));
  } else {
    DPU_FOREACH(dpu_set, dpu, idx_dpu) {
      CHECK_UPMEM(dpu_prepare_xfer(dpu, &args[idx_dpu]));
    }
    CHECK_UPMEM(dpu_push_xfer(dpu_set, DPU_XFER_TO_DPU, "args", 0,
                              sizeof(args[0]), DPU_XFER_DEFAULT));
  }
  CHECK_UPMEM(dpu_launch(dpu_set, DPU_ASYNCHRONOUS));
}
#endif

void launch_unary(VectorDescRef res, VectorDescRef rhs, KernelID kernel_id,
                  uint8_t opcode, KernelID pipeline_kid) {
  auto& runtime = DpuRuntime::get();
  auto& event_queue = runtime.get_event_queue();

#if PIPELINE
  std::shared_ptr<Event> e = std::make_shared<Event>(
      Event::OperationType::COMPUTE,
      std::bind(internal_launch_unary, res, rhs, kernel_id));
  e->pipeline_kid = pipeline_kid;
#else
  (void)pipeline_kid;
  auto bound_cb = std::bind(internal_launch_unary, res, rhs, kernel_id);
  std::shared_ptr<Event> e =
      std::make_shared<Event>(Event::OperationType::COMPUTE, bound_cb);
#endif
  e->inputs = {rhs};
  e->output = res;
  e->kid = kernel_id;
  e->opcode = opcode;
  event_queue.submit(e);

#if ENABLE_DPU_LOGGING >= 2
  Logger& logger = DpuRuntime::get().get_logger();
  logger.lock(logcat::QUEUE_APPEND, 2)
      << "type=COMPUTE (unary) kernel=" << kernel_id_to_string(kernel_id)
      << std::endl;
#endif
}

#if PIPELINE
void launch_universal_pipeline(
    VectorDescRef res, VectorDescRef init, const std::vector<uint8_t>& ops,
    const std::vector<VectorDescRef>& operands, KernelID kernel_id,
    const std::vector<uint32_t>& scalars,
    const std::vector<uint32_t>& extra_scalars,
    const std::vector<VectorDescRef>& extra_outputs) {
  auto& runtime = DpuRuntime::get();
  auto& event_queue = runtime.get_event_queue();

  std::shared_ptr<Event> e =
      std::make_shared<Event>(Event::OperationType::COMPUTE);

  e->inputs = {init};
  for (auto& op : operands) {
    if (op) e->inputs.push_back(op);
  }
  e->output = res;
  e->rpn_ops = ops;
  e->kid = kernel_id;
  // The interpreter path dispatches pipeline_kid, and the universal pipeline is
  // the only kernel that can run an arbitrary RPN program -- so it is both.
  // Leaving it 0 silently ran kernel 0 (binary add) for every explicit
  // pipeline() call under JIT=0.
  e->pipeline_kid = kernel_id;
  e->scalars = scalars;
  e->extra_scalars = extra_scalars;
  e->extra_outputs = extra_outputs;

  // Detect reduction and flag result descriptor synchronously
  for (size_t i = 0; i < ops.size(); ++i) {
    uint8_t op = ops[i];
    if (res && IS_OP_REDUCTION(op)) {
      res->is_reduction_result = true;
      res->reduction_rid = static_cast<KernelID>(op);
    }
    if (OP_INLINE_BYTES(op) > 0) i += OP_INLINE_BYTES(op);
  }

  event_queue.submit(e);
}
#endif

void launch_binary(VectorDescRef res, VectorDescRef lhs, VectorDescRef rhs,
                   KernelID kernel_id, uint8_t opcode, KernelID pipeline_kid) {
  auto& runtime = DpuRuntime::get();
  auto& event_queue = runtime.get_event_queue();

#if PIPELINE
  assert(lhs->num_elements == rhs->num_elements);

  std::shared_ptr<Event> e = std::make_shared<Event>(
      Event::OperationType::COMPUTE,
      std::bind(internal_launch_binary, res, lhs, rhs, kernel_id));

  e->pipeline_kid = pipeline_kid;
#else
  (void)pipeline_kid;
  auto bound_cb = std::bind(internal_launch_binary, res, lhs, rhs, kernel_id);
  std::shared_ptr<Event> e =
      std::make_shared<Event>(Event::OperationType::COMPUTE, bound_cb);
#endif
  e->inputs = {lhs, rhs};
  e->output = res;
  e->kid = kernel_id;
  e->opcode = opcode;
  event_queue.submit(e);

#if ENABLE_DPU_LOGGING >= 2
  Logger& logger = DpuRuntime::get().get_logger();
  logger.lock(logcat::QUEUE_APPEND, 2)
      << "type=COMPUTE (binary) kernel=" << kernel_id_to_string(kernel_id)
      << std::endl;
#endif
}

void launch_binary_scalar(VectorDescRef res, VectorDescRef lhs, uint32_t scalar,
                          KernelID kernel_id, uint8_t opcode,
                          KernelID pipeline_kid) {
  auto& runtime = DpuRuntime::get();
  auto& event_queue = runtime.get_event_queue();

#if PIPELINE
  std::shared_ptr<Event> e = std::make_shared<Event>(
      Event::OperationType::COMPUTE,
      std::bind(internal_launch_binary_scalar, res, lhs, scalar, kernel_id));
  e->pipeline_kid = pipeline_kid;
#else
  (void)pipeline_kid;
  auto bound_cb =
      std::bind(internal_launch_binary_scalar, res, lhs, scalar, kernel_id);
  std::shared_ptr<Event> e =
      std::make_shared<Event>(Event::OperationType::COMPUTE, bound_cb);
#endif
  e->is_scalar = true;
  e->scalar_value = scalar;
  e->inputs = {lhs};
  e->output = res;
  e->kid = kernel_id;
  e->opcode = opcode;
  event_queue.submit(e);

#if ENABLE_DPU_LOGGING >= 2
  Logger& logger = DpuRuntime::get().get_logger();
  logger.lock(logcat::QUEUE_APPEND, 2)
      << "type=COMPUTE (binary_scalar) kernel="
      << kernel_id_to_string(kernel_id) << std::endl;
#endif
}

void launch_reduction(VectorDescRef res, VectorDescRef rhs, KernelID kernel_id,
                      uint8_t opcode, KernelID pipeline_kid) {
  auto& runtime = DpuRuntime::get();
  auto& event_queue = runtime.get_event_queue();

#if PIPELINE
  std::shared_ptr<Event> e = std::make_shared<Event>(
      Event::OperationType::COMPUTE,
      std::bind(internal_launch_reduction, res, rhs, kernel_id));

  e->pipeline_kid = pipeline_kid;
  // Mark result description as reduction synchronously
  res->is_reduction_result = true;
  res->reduction_rid = static_cast<KernelID>(opcode);
#else
  (void)pipeline_kid;
  auto bound_cb = std::bind(internal_launch_reduction, res, rhs, kernel_id);
  std::shared_ptr<Event> e =
      std::make_shared<Event>(Event::OperationType::COMPUTE, bound_cb);
#endif
  e->inputs = {rhs};
  e->output = res;
  e->kid = kernel_id;
  e->opcode = opcode;
  event_queue.submit(e);

#if ENABLE_DPU_LOGGING >= 2
  Logger& logger = DpuRuntime::get().get_logger();
  logger.lock(logcat::QUEUE_APPEND, 2)
      << "type=COMPUTE (reduction) kernel=" << kernel_id_to_string(kernel_id)
      << std::endl;
#endif
}

}  // namespace detail
