#include <ATen/core/dispatch/Dispatcher.h>
#include <torch/library.h>
#include <c10/util/irange.h>
#include <c10/core/impl/FakeTensorModeTLS.h>
#include <c10/core/impl/LocalDispatchKeySet.h>

namespace {

static bool has_python_key_arg(
    torch::jit::Stack* stack,
    size_t num_arguments) {
  auto arguments = torch::jit::last(*stack, num_arguments);
  for (size_t idx = 0; idx < num_arguments; ++idx) {
    const auto& ivalue = arguments[idx];
    if (ivalue.isTensor()) {
      const auto& t = ivalue.toTensor();
      if (t.defined() && t.key_set().has(c10::DispatchKey::Python)) {
        return true;
      }
    } else if (ivalue.isTensorList()) {
      for (const auto& elem : ivalue.toTensorList()) {
        at::Tensor t = elem;
        if (t.defined() && t.key_set().has(c10::DispatchKey::Python)) {
          return true;
        }
      }
    } else if (ivalue.isOptionalTensorList()) {
      for (const auto& elem : ivalue.toOptionalTensorList()) {
        std::optional<at::Tensor> ot = elem;
        if (ot.has_value() && ot->defined() &&
            ot->key_set().has(c10::DispatchKey::Python)) {
          return true;
        }
      }
    }
  }
  return false;
}

// Determine the output device from fake tensor inputs, or nullopt for factory ops.
static std::optional<c10::Device> get_common_device(
    torch::jit::Stack* stack,
    size_t num_arguments) {
  std::optional<c10::Device> common_device;
  bool is_cpu_zero_dim = false;

  auto merge = [&](const at::Tensor& t) {
    if (!t.defined() || !t.is_fake()) return;
    bool t_is_cpu_zero_dim = t.device().is_cpu() && t.dim() == 0;
    if (!common_device.has_value()) {
      common_device = t.device();
      is_cpu_zero_dim = t_is_cpu_zero_dim;
      return;
    }
    if (t.device() == *common_device) {
      if (is_cpu_zero_dim) is_cpu_zero_dim = t_is_cpu_zero_dim;
      return;
    }
    if (t_is_cpu_zero_dim) return;
    TORCH_CHECK(is_cpu_zero_dim,
        "Unhandled FakeTensor device propagation: ", *common_device, " vs ", t.device());
    common_device = t.device();
    is_cpu_zero_dim = false;
  };

  auto arguments = torch::jit::last(*stack, num_arguments);
  for (size_t idx = 0; idx < num_arguments; ++idx) {
    const auto& ivalue = arguments[idx];
    if (ivalue.isTensor()) {
      merge(ivalue.toTensor());
    } else if (ivalue.isTensorList()) {
      for (const auto& elem : ivalue.toTensorList()) merge(elem);
    } else if (ivalue.isOptionalTensorList()) {
      for (const auto& elem : ivalue.toOptionalTensorList()) {
        std::optional<at::Tensor> ot = elem;
        if (ot.has_value()) merge(*ot);
      }
    }
  }
  return common_device;
}

// For factory ops: find Device args in the stack, rewrite to meta, return original.
static std::optional<c10::Device> rewrite_device_args_to_meta(
    torch::jit::Stack* stack,
    size_t arguments_begin,
    size_t num_arguments) {
  std::optional<c10::Device> original_device;
  auto arguments = torch::jit::last(*stack, num_arguments);
  for (size_t idx = 0; idx < num_arguments; ++idx) {
    const auto& ivalue = arguments[idx];
    if (ivalue.isDevice()) {
      auto dev = ivalue.toDevice();
      TORCH_CHECK(dev.type() != c10::DeviceType::Meta,
          "FakeTensor does not support meta device inputs");
      if (!original_device.has_value()) original_device = dev;
      (*stack)[arguments_begin + idx] =
          c10::IValue(c10::Device(c10::DeviceType::Meta));
    }
  }
  return original_device;
}

static void transmute_to_fake(
    const at::Tensor& t,
    c10::Device fake_device,
    const std::shared_ptr<c10::FakeTensorMode>& mode) {
  t.unsafeGetTensorImpl()->set_fake_device(fake_device);
  if (mode) {
    t.unsafeGetTensorImpl()->set_fake_tensor_mode(mode);
  }
}

static void wrap_outputs(
    torch::jit::Stack* stack,
    size_t returns_begin,
    size_t num_returns,
    c10::Device fake_device,
    const std::shared_ptr<c10::FakeTensorMode>& mode) {
  auto returns = torch::jit::last(*stack, num_returns);
  for (size_t idx = 0; idx < num_returns; ++idx) {
    const auto& ivalue = returns[idx];
    if (ivalue.isTensor()) {
      const auto& t = ivalue.toTensor();
      if (t.defined() && !t.is_fake()) {
        transmute_to_fake(t, fake_device, mode);
      }
    } else if (ivalue.isTensorList()) {
      auto tensors = ivalue.toTensorList();
      for (const auto i : c10::irange(tensors.size())) {
        at::Tensor t = tensors[i];
        if (t.defined() && !t.is_fake()) {
          transmute_to_fake(t, fake_device, mode);
        }
      }
    } else if (ivalue.isOptionalTensorList()) {
      auto opt_tensors = ivalue.toOptionalTensorList();
      for (const auto i : c10::irange(opt_tensors.size())) {
        std::optional<at::Tensor> ot = opt_tensors[i];
        if (ot.has_value() && ot->defined() && !ot->is_fake()) {
          transmute_to_fake(*ot, fake_device, mode);
        }
      }
    }
  }
}

void fakeFallback(
    const c10::OperatorHandle& op,
    c10::DispatchKeySet dispatchKeySet,
    torch::jit::Stack* stack) {
  const auto& schema = op.schema();
  const auto num_arguments = schema.arguments().size();
  const auto arguments_begin = stack->size() - num_arguments;

  if (has_python_key_arg(stack, num_arguments)) {
    op.redispatchBoxed(dispatchKeySet.remove(c10::DispatchKey::Fake), stack);
    return;
  }

  // 2. Determine fake device and mode from inputs
  auto fake_device = get_common_device(stack, num_arguments);
  auto mode = c10::impl::FakeTensorModeTLS::get_state();

  // 3. For factory ops (no fake tensor inputs), rewrite device args to meta
  if (!fake_device.has_value()) {
    fake_device = rewrite_device_args_to_meta(
        stack, arguments_begin, num_arguments);
    if (!fake_device.has_value()) {
      fake_device = c10::Device(c10::DeviceType::CPU);
    }
  }

  // 4. Redispatch to the meta kernel.
  {
    c10::impl::ExcludeDispatchKeyGuard fake_guard(c10::DispatchKey::Fake);
    c10::impl::ExcludeDispatchKeyGuard python_guard(c10::DispatchKey::Python);
    c10::impl::ExcludeDispatchKeyGuard python_tls_guard(
        c10::DispatchKey::PythonTLSSnapshot);
    c10::impl::IncludeDispatchKeyGuard meta_guard(c10::DispatchKey::Meta);
    op.redispatchBoxed(dispatchKeySet.remove(c10::DispatchKey::Fake), stack);
  }

  // 5. Wrap outputs as fake tensors
  const auto num_returns = schema.returns().size();
  const auto returns_begin = stack->size() - num_returns;
  wrap_outputs(stack, returns_begin, num_returns, *fake_device, mode);
}

TORCH_LIBRARY_IMPL(_, Fake, m) {
  m.fallback(torch::CppFunction::makeFromBoxedFunction<&fakeFallback>());
}

} // anonymous namespace
