// ignis kernel leaf - Ticket 04: flat C ABI device-surface (ADR 0001).
//
// Implements the C ABI functions declared in include/ignis_device.h. One
// device handle owns a dedicated non-blocking load stream and a blocking-sync
// event (the reference `DeviceContext` pattern: the blocking-sync event makes
// `synchronize()` sleep instead of CPU-spinning on the stream). Style follows
// the ticket-01 leaf (hello.cu): explicit pointers + sizes, int32 return
// codes (0 = ok, -1 = CUDA error / bad argument), no C++ types across the
// boundary.
//
// NOTE: this module never runs in the default (CPU) build — it is linked only
// when the `cuda` cargo feature is enabled. ADR 0006: the RTX 5090 is held by
// the reference `ninfer-serve`, so real CUDA uploads are gated (the Rust
// `CudaDevice` skips unless `IGNIS_TEST_CUDA=1` and the GPU is free).

#include "ignis_device.h"
#include "ignis_seq.h"
#include "shared_library.h"

#include <cuda_runtime.h>
#include <nvml.h>

#include <cstdint>
#include <cstdio>
#include <cstdlib>

struct ignis_device {
  cudaStream_t load_stream;
  cudaEvent_t blocking_sync;
  int device_id;
};

namespace {

// NVML ships with the driver, not the toolkit, so it is opened when first
// asked for rather than linked: a binary that names it on its link line does
// not start where there is no driver (GitHub #329). nvml.h is here for the
// entry points' types; they are looked up by their exported names.
#ifdef _WIN32
constexpr const char *kNvmlLibrary = "nvml.dll";
#else
constexpr const char *kNvmlLibrary = "libnvidia-ml.so.1";
#endif

struct Nvml {
  decltype(&nvmlInit_v2) init;
  decltype(&nvmlShutdown) shutdown;
  decltype(&nvmlErrorString) error_string;
  decltype(&nvmlDeviceGetHandleByPciBusId_v2) handle_by_pci_bus_id;
  decltype(&nvmlDeviceGetMemoryInfo) memory_info;
};

template <typename Fn>
bool resolve_nvml(void *library, const char *symbol, Fn *out) {
  *out = reinterpret_cast<Fn>(ignis::shared_library_symbol(library, symbol));
  if (*out == nullptr) {
    std::fprintf(stderr, "[ignis-device] NVML: %s has no %s\n", kNvmlLibrary, symbol);
  }
  return *out != nullptr;
}

// The NVML entry points, opened once; nullptr (said once, on stderr) when the
// library does not load or lacks one of them.
const Nvml *nvml() {
  static const Nvml *const api = []() -> const Nvml * {
    void *library = ignis::open_shared_library(kNvmlLibrary);
    if (library == nullptr) {
      std::fprintf(stderr, "[ignis-device] NVML: %s does not load\n", kNvmlLibrary);
      return nullptr;
    }
    static Nvml table{};
    const bool resolved = resolve_nvml(library, "nvmlInit_v2", &table.init) &&
                          resolve_nvml(library, "nvmlShutdown", &table.shutdown) &&
                          resolve_nvml(library, "nvmlErrorString", &table.error_string) &&
                          resolve_nvml(library, "nvmlDeviceGetHandleByPciBusId_v2",
                                       &table.handle_by_pci_bus_id) &&
                          resolve_nvml(library, "nvmlDeviceGetMemoryInfo", &table.memory_info);
    return resolved ? &table : nullptr;
  }();
  return api;
}

// Log a CUDA error (never aborts from a leaf: the caller decides the -1/NULL
// path). Returns the caller's own return value (kept separate from logging).
template <typename T>
T log_cuda_error(T value, const char *op, cudaError_t err) {
  if (err != cudaSuccess) {
    std::fprintf(stderr, "[ignis-device] CUDA error in %s: %s: %s\n", op,
                 cudaGetErrorName(err), cudaGetErrorString(err));
  }
  return value;
}

// Ensure the handle's device is current (the load stream + event are bound to
// it). Returns true on success, false (already logged) on a CUDA error.
bool ensure_device(struct ignis_device *d) {
  cudaError_t err = cudaSetDevice(d->device_id);
  if (err != cudaSuccess) {
    log_cuda_error(false, "cudaSetDevice", err);
    return false;
  }
  return true;
}

}  // namespace

// GitHub #211: kernel/src/seq.cu keeps the allocation counter.
void ignis_alloc_count_record(std::int32_t kind, bool alloc, std::uint64_t bytes);

extern "C" struct ignis_device *ignis_device_create(int device_id) {
  int count = 0;
  cudaError_t err = cudaGetDeviceCount(&count);
  if (err != cudaSuccess) {
    log_cuda_error(nullptr, "cudaGetDeviceCount", err);
    return nullptr;
  }
  if (count <= 0) {
    std::fprintf(stderr, "[ignis-device] no CUDA devices available\n");
    return nullptr;
  }
  if (device_id < 0 || device_id >= count) {
    std::fprintf(stderr, "[ignis-device] invalid device id %d (have %d)\n", device_id, count);
    return nullptr;
  }

  err = cudaSetDevice(device_id);
  if (err != cudaSuccess) {
    log_cuda_error(nullptr, "cudaSetDevice", err);
    return nullptr;
  }

  struct ignis_device *d =
      static_cast<struct ignis_device *>(std::calloc(1, sizeof(struct ignis_device)));
  if (d == nullptr) {
    std::fprintf(stderr, "[ignis-device] allocation failed\n");
    return nullptr;
  }
  d->device_id = device_id;

  // Dedicated non-blocking load stream: keeps the materialization H2D copies
  // off the default (blocking) stream.
  err = cudaStreamCreateWithFlags(&d->load_stream, cudaStreamNonBlocking);
  if (err != cudaSuccess) {
    log_cuda_error(nullptr, "cudaStreamCreateWithFlags(load)", err);
    std::free(d);
    return nullptr;
  }

  // A blocking-sync event makes `synchronize()` sleep instead of spinning a
  // host core (the reference DeviceContext pattern, the fix for the 100% CPU
  // observed during loads).
  err = cudaEventCreateWithFlags(&d->blocking_sync, cudaEventDisableTiming | cudaEventBlockingSync);
  if (err != cudaSuccess) {
    log_cuda_error(nullptr, "cudaEventCreateWithFlags(sync)", err);
    cudaStreamDestroy(d->load_stream);
    std::free(d);
    return nullptr;
  }

  return d;
}

extern "C" int32_t ignis_device_alloc(struct ignis_device *d, uint64_t bytes, void **out_ptr) {
  if (d == nullptr || out_ptr == nullptr) {
    return -1;
  }
  if (!ensure_device(d)) {
    return -1;
  }
  void *ptr = nullptr;
  cudaError_t err = cudaMalloc(&ptr, bytes);
  if (err != cudaSuccess) {
    return log_cuda_error(-1, "cudaMalloc", err);
  }
  ignis_alloc_count_record(IGNIS_ALLOC_DEVICE, true, bytes);
  *out_ptr = ptr;
  return 0;
}

extern "C" int32_t ignis_device_copy_h2d(struct ignis_device *d, void *dst, const void *src,
                                         uint64_t bytes) {
  if (d == nullptr) {
    return -1;
  }
  if (bytes == 0) {
    return 0;  // empty copy is a no-op (nothing to enqueue)
  }
  if (!ensure_device(d)) {
    return -1;
  }
  cudaError_t err =
      cudaMemcpyAsync(dst, src, bytes, cudaMemcpyHostToDevice, d->load_stream);
  if (err != cudaSuccess) {
    return log_cuda_error(-1, "cudaMemcpyAsync(H2D)", err);
  }
  return 0;
}

extern "C" int32_t ignis_device_copy_d2h(struct ignis_device *d, void *dst, const void *src,
                                         uint64_t bytes) {
  if (d == nullptr) {
    return -1;
  }
  if (bytes == 0) {
    return 0;  // empty copy is a no-op (nothing to enqueue)
  }
  if (!ensure_device(d)) {
    return -1;
  }
  cudaError_t err =
      cudaMemcpyAsync(dst, src, bytes, cudaMemcpyDeviceToHost, d->load_stream);
  if (err != cudaSuccess) {
    return log_cuda_error(-1, "cudaMemcpyAsync(D2H)", err);
  }
  return 0;
}

extern "C" int32_t ignis_device_sync(struct ignis_device *d) {
  if (d == nullptr) {
    return -1;
  }
  if (!ensure_device(d)) {
    return -1;
  }
  cudaError_t err = cudaEventRecord(d->blocking_sync, d->load_stream);
  if (err != cudaSuccess) {
    return log_cuda_error(-1, "cudaEventRecord", err);
  }
  // The blocking-sync event sleeps (no CPU spin) until the stream drains.
  err = cudaEventSynchronize(d->blocking_sync);
  if (err != cudaSuccess) {
    return log_cuda_error(-1, "cudaEventSynchronize", err);
  }
  return 0;
}

extern "C" int32_t ignis_device_driver_version(int32_t *version) {
  if (version == nullptr) {
    return -1;
  }
  // The runtime loads the driver's library here, if there is one; with none
  // it reports version 0 (GitHub #329). No context is created.
  int driver_version = 0;
  cudaError_t err = cudaDriverGetVersion(&driver_version);
  if (err != cudaSuccess) {
    return log_cuda_error(-1, "cudaDriverGetVersion", err);
  }
  *version = driver_version;
  return 0;
}

extern "C" int32_t ignis_device_runtime_version(int32_t *version) {
  if (version == nullptr) {
    return -1;
  }
  int runtime_version = 0;
  cudaError_t err = cudaRuntimeGetVersion(&runtime_version);
  if (err != cudaSuccess) {
    return log_cuda_error(-1, "cudaRuntimeGetVersion", err);
  }
  *version = runtime_version;
  return 0;
}

extern "C" int32_t ignis_device_nvml_mem_info(int device_id, uint64_t *free_bytes,
                                              uint64_t *total_bytes) {
  if (free_bytes == nullptr || total_bytes == nullptr) {
    return -1;
  }
  // The PCI bus id names the same card in both APIs, whatever order each
  // enumerates devices in; asking for it creates no context.
  char bus_id[NVML_DEVICE_PCI_BUS_ID_BUFFER_SIZE] = {};
  cudaError_t err = cudaDeviceGetPCIBusId(bus_id, sizeof(bus_id), device_id);
  if (err != cudaSuccess) {
    return log_cuda_error(-1, "cudaDeviceGetPCIBusId", err);
  }
  const Nvml *api = nvml();
  if (api == nullptr) {
    return -1;
  }
  nvmlReturn_t rc = api->init();
  if (rc != NVML_SUCCESS) {
    std::fprintf(stderr, "[ignis-device] NVML error in nvmlInit_v2: %s\n", api->error_string(rc));
    return -1;
  }
  nvmlDevice_t device = nullptr;
  nvmlMemory_t memory{};
  rc = api->handle_by_pci_bus_id(bus_id, &device);
  const char *op = "nvmlDeviceGetHandleByPciBusId_v2";
  if (rc == NVML_SUCCESS) {
    rc = api->memory_info(device, &memory);
    op = "nvmlDeviceGetMemoryInfo";
  }
  if (rc != NVML_SUCCESS) {
    std::fprintf(stderr, "[ignis-device] NVML error in %s: %s\n", op, api->error_string(rc));
  }
  api->shutdown();
  if (rc != NVML_SUCCESS) {
    return -1;
  }
  *free_bytes = memory.free;
  *total_bytes = memory.total;
  return 0;
}

extern "C" int32_t ignis_device_mem_info(struct ignis_device *d, uint64_t *free_bytes,
                                         uint64_t *total_bytes) {
  if (d == nullptr || free_bytes == nullptr || total_bytes == nullptr) {
    return -1;
  }
  if (!ensure_device(d)) {
    return -1;
  }
  size_t free_sz = 0;
  size_t total_sz = 0;
  cudaError_t err = cudaMemGetInfo(&free_sz, &total_sz);
  if (err != cudaSuccess) {
    return log_cuda_error(-1, "cudaMemGetInfo", err);
  }
  *free_bytes = static_cast<uint64_t>(free_sz);
  *total_bytes = static_cast<uint64_t>(total_sz);
  return 0;
}

extern "C" void ignis_device_free(struct ignis_device *d, void *ptr) {
  if (d == nullptr || ptr == nullptr) {
    return;
  }
  if (!ensure_device(d)) {
    return;
  }
  ignis_alloc_count_record(IGNIS_ALLOC_DEVICE, false, 0);
  cudaError_t err = cudaFree(ptr);
  if (err != cudaSuccess) {
    log_cuda_error(0, "cudaFree", err);
  }
}

extern "C" void ignis_device_destroy(struct ignis_device *d) {
  if (d == nullptr) {
    return;
  }
  if (ensure_device(d)) {
    // Drain the load stream before destroying it (frees any pending work).
    cudaStreamSynchronize(d->load_stream);
    cudaEventDestroy(d->blocking_sync);
    cudaStreamDestroy(d->load_stream);
  }
  std::free(d);
}