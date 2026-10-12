/*
 * Copyright 2021 Alyssa Rosenzweig
 * Copyright 2019 Collabora, Ltd.
 * Copyright 2020 Igalia S.L.
 * SPDX-License-Identifier: MIT
 */

#include "agx_device.h"
#include "agx_g17p_bind0.h"
#include "agx_linker.h"
#include "agx_va_runtime_hole.h"
#include <errno.h>
#include <stdlib.h>
#include <inttypes.h>
#include "clc/asahi_clc.h"
#include "drm-uapi/asahi_drm.h"
#include "util/bitscan.h"
#include "util/macros.h"
#include "util/ralloc.h"
#include "util/timespec.h"
#include "agx_abi.h"
#include "agx_bo.h"
#include "agx_compile.h"
#include "agx_device_virtio.h"
#include "agx_scratch.h"
#include "decode.h"
#include "glsl_types.h"
#include "layout.h"
#include "libagx_dgc.h"
#include "libagx_shaders.h"

#include <fcntl.h>
#ifdef HAVE_LIBDRM
#include <xf86drm.h>
#include "drm-uapi/dma-buf.h"
#include "vdrm.h"
#endif
#include "util/blob.h"
#include "util/log.h"
#include "util/mesa-blake3.h"
#include "util/os_file.h"
#ifdef HAVE_LIBDRM
#include "util/os_mman.h"
#endif
#include "util/os_time.h"
#include "util/simple_mtx.h"
#include "util/u_math.h"
#include "util/u_printf.h"
#include "git_sha1.h"
#include "nir_serialize.h"
#ifdef _WIN32
#include "agx_device_d3dkmt.h"
#endif

/*
 * honeykrisp-h1-execution.md SS1/SS2.1: promoted from `static inline` to a
 * plain external function so it can be installed as the `simple_ioctl` op
 * (agx_device.h) in BOTH agx_device_drm_ops (below) and
 * agx_virtio_device_ops (agx_device_virtio.c) -- it already dispatches on
 * dev->is_virtio itself, so one function correctly backs both instances.
 * HAVE_LIBDRM-only: the Windows winsys (agx_device_win.c) installs its own
 * win_simple_ioctl in agx_device_win_ops instead.
 */
#ifdef HAVE_LIBDRM
int
asahi_simple_ioctl(struct agx_device *dev, unsigned cmd, void *req)
{
   if (dev->is_virtio) {
      return agx_virtio_simple_ioctl(dev, cmd, req);
   } else {
      return drmIoctl(dev->fd, cmd, req);
   }
}

/*
 * honeykrisp-h1-execution.md SS1/SS2.1: Linux body for the `bo_munmap` op.
 * Installed in both agx_device_drm_ops and agx_virtio_device_ops -- plain
 * munmap(2) behavior doesn't differ between the two Linux backends.
 */
void
agx_drm_bo_munmap(struct agx_device *dev, struct agx_bo *bo)
{
   munmap(bo->_map, bo->size);
}

int
agx_drm_bo_sync_for_device(struct agx_device *dev, struct agx_bo *bo,
                           size_t offset, size_t size)
{
   (void)dev;
   (void)bo;
   (void)offset;
   (void)size;
   return 0;
}

/*
 * honeykrisp-h1-execution.md SS1/SS2.1: Linux body for the `bo_free` op
 * (the DRM_IOCTL_GEM_CLOSE tail of the former inline agx_bo_free()).
 * Installed in agx_device_drm_ops. The virtio backend must also flush
 * buffered host commands before closing the local GEM handle.
 */
void
agx_drm_bo_close(struct agx_device *dev, uint32_t handle)
{
   struct drm_gem_close args = {.handle = handle};
   drmIoctl(dev->fd, DRM_IOCTL_GEM_CLOSE, &args);
}
#endif /* HAVE_LIBDRM */

/* clang-format off */
static const struct debug_named_value agx_debug_options[] = {
   {"trace",     AGX_DBG_TRACE,    "Trace the command stream"},
   {"bodump",    AGX_DBG_BODUMP,   "Periodically dump live BOs"},
   {"no16",      AGX_DBG_NO16,     "Disable 16-bit support"},
   {"perf",      AGX_DBG_PERF,     "Print performance warnings"},
#ifndef NDEBUG
   {"dirty",     AGX_DBG_DIRTY,    "Disable dirty tracking"},
#endif
   {"precompile",AGX_DBG_PRECOMPILE,"Precompile shaders for shader-db"},
   {"nocompress",AGX_DBG_NOCOMPRESS,"Disable lossless compression"},
   {"nocluster", AGX_DBG_NOCLUSTER,"Disable vertex clustering"},
   {"sync",      AGX_DBG_SYNC,     "Synchronously wait for all submissions"},
   {"stats",     AGX_DBG_STATS,    "Show command execution statistics"},
   {"resource",  AGX_DBG_RESOURCE, "Log resource operations"},
   {"batch",     AGX_DBG_BATCH,    "Log batches"},
   {"nowc",      AGX_DBG_NOWC,     "Disable write-combining"},
   {"synctvb",   AGX_DBG_SYNCTVB,  "Synchronous TVB growth"},
   {"smalltile", AGX_DBG_SMALLTILE,"Force 16x16 tiles"},
   {"feedback",  AGX_DBG_FEEDBACK, "Debug feedback loops"},
   {"nomsaa",    AGX_DBG_NOMSAA,   "Force disable MSAA"},
   {"noshadow",  AGX_DBG_NOSHADOW, "Force disable resource shadowing"},
   {"scratch",   AGX_DBG_SCRATCH,  "Debug scratch memory usage"},
   {"1queue",    AGX_DBG_1QUEUE,   "Force usage of a single queue for multiple contexts"},
   {"nosoft",    AGX_DBG_NOSOFT,   "Disable soft fault optimizations"},
   {"nomerge",   AGX_DBG_NOMERGE,  "Disable control stream merging"},
   {"bodumpverbose", AGX_DBG_BODUMPVERBOSE,   "Include extra info with dumps"},
   DEBUG_NAMED_VALUE_END
};
/* clang-format on */

void
agx_bo_free(struct agx_device *dev, struct agx_bo *bo)
{
   const uint64_t handle = bo->handle;

   if (bo->_map)
      dev->ops.bo_munmap(dev, bo);

   /* Free the VA. No need to unmap the BO or unbind the VA, as the kernel will
    * take care of that when we close it.
    */
   agx_va_free(dev, bo->va, false);

#ifdef HAVE_LIBDRM
   /* prime_fd is always -1 on Windows (no dma-buf import path, SS2.1). */
   if (bo->prime_fd != -1)
      close(bo->prime_fd);
#endif

   /* Reset the handle. This has to happen before the GEM close to avoid a race.
    */
   memset(bo, 0, sizeof(*bo));
   __sync_synchronize();

   dev->ops.bo_free(dev, handle);
}

#ifdef HAVE_LIBDRM
static int
agx_drm_bo_bind(struct agx_device *dev, struct drm_asahi_gem_bind_op *ops,
                uint32_t count)
{
   struct drm_asahi_vm_bind vm_bind = {
      .num_binds = count,
      .vm_id = dev->vm_id,
      .userptr = (uintptr_t)ops,
      .stride = sizeof(*ops),
   };

   int ret = drmIoctl(dev->fd, DRM_IOCTL_ASAHI_VM_BIND, &vm_bind);
   if (ret) {
      fprintf(stderr, "DRM_IOCTL_ASAHI_VM_BIND failed: %s (vm=%u count=%u addr=%#llx size=%#llx flags=%#x)\n",
              strerror(errno), dev->vm_id, count,
              (unsigned long long)(count ? ops[0].addr : 0),
              (unsigned long long)(count ? ops[0].range : 0),
              count ? ops[0].flags : 0);
   }

   return ret;
}
#endif /* HAVE_LIBDRM */

/*
 * Convenience helper to bind a single BO regardless of kernel module.
 */
int
agx_bo_bind(struct agx_device *dev, struct agx_bo *bo, uint64_t addr,
            size_t size_B, uint64_t offset_B, uint32_t flags)
{
   assert((size_B % 16384) == 0 && "alignment required");
   assert((offset_B % 16384) == 0 && "alignment required");
   assert((addr % 16384) == 0 && "alignment required");

   if (agx_va_overlaps_runtime_graph_hole(dev->chip, addr, size_B)) {
      errno = EINVAL;
      return -1;
   }

   struct drm_asahi_gem_bind_op op = {
      .flags = flags,
      .handle = bo ? bo->uapi_handle : 0,
      .offset = offset_B,
      .range = size_B,
      .addr = addr,
   };

   return dev->ops.bo_bind(dev, &op, 1);
}

/*
 * Metal's HAL200 render context is six independently allocated resources.
 * The first five are 32 KiB and the last is 48 KiB.  Each resource has a
 * compact high mapping and an identity low alias in the render VM:
 *
 *   0x1000018000 -> 0x18000, ..., 0x1000068000 -> 0x68000
 *
 * Honeykrisp intentionally combines those resources into one fixed BO at
 * 0x1000000000, preserving the exact high addresses as BO offsets.  Bind the
 * corresponding ranges a second time so hardware-side direct-context reads
 * see the same low aperture as Metal.  The resource sizes and gaps are
 * trace-observed; do not turn this into one broad low mapping.
 */
static const struct {
   uint64_t offset;
   uint64_t size;
} agx_g17p_render_context_low_slots[] = {
   {UINT64_C(0x18000), UINT64_C(0x8000)},
   {UINT64_C(0x28000), UINT64_C(0x8000)},
   {UINT64_C(0x38000), UINT64_C(0x8000)},
   {UINT64_C(0x48000), UINT64_C(0x8000)},
   {UINT64_C(0x58000), UINT64_C(0x8000)},
   {UINT64_C(0x68000), UINT64_C(0xc000)},
};

static void
agx_g17p_unbind_render_context_low_slots(struct agx_device *dev,
                                         unsigned count)
{
   for (unsigned i = 0; i < count; ++i) {
      const uint64_t slot = agx_g17p_render_context_low_slots[i].offset;
      const uint64_t size = agx_g17p_render_context_low_slots[i].size;
      agx_bo_bind(dev, NULL, slot, size, 0, DRM_ASAHI_BIND_UNBIND);
   }
}

static bool
agx_g17p_bind_render_context_low_slots(struct agx_device *dev,
                                       struct agx_bo *context)
{
   const uint32_t flags = DRM_ASAHI_BIND_READ | DRM_ASAHI_BIND_WRITE;

   for (unsigned i = 0;
        i < ARRAY_SIZE(agx_g17p_render_context_low_slots); ++i) {
      const uint64_t slot = agx_g17p_render_context_low_slots[i].offset;
      const uint64_t size = agx_g17p_render_context_low_slots[i].size;

      if (agx_bo_bind(dev, context, slot, size, slot, flags)) {
         fprintf(stderr,
                 "Failed to bind G17P render-context low slot %#llx\n",
                 (unsigned long long)slot);
         agx_g17p_unbind_render_context_low_slots(dev, i);
         return false;
      }
   }

   return true;
}

int
agx_bind_timestamps(struct agx_device *dev, struct agx_bo *bo, uint32_t *handle)
{
   struct drm_asahi_gem_bind_object bind = {
      .op = DRM_ASAHI_BIND_OBJECT_OP_BIND,
      .flags = DRM_ASAHI_BIND_OBJECT_USAGE_TIMESTAMPS,
      .handle = bo->uapi_handle,
      .range = bo->size,
   };

   int ret = dev->ops.bo_bind_object(dev, &bind);
   *handle = bind.object_handle;
   return ret;
}

/*
 * honeykrisp-h1-execution.md SS2.1: everything from here through
 * `agx_device_drm_ops` below is the Linux/libdrm backend body -- the
 * counterpart of agx_device_win.c's win_* functions and
 * agx_device_win_ops. `agx_bo_import`/`agx_bo_export` get Windows stubs
 * (row ":266..."): both are called unconditionally from
 * hk_device_memory.c (behind extensions that are themselves disabled on
 * Windows per SS2.2 row P2, but the C call sites still need something to
 * link against).
 */
#ifdef HAVE_LIBDRM
static struct agx_bo *
agx_bo_alloc(struct agx_device *dev, size_t size, size_t align,
             enum agx_bo_flags flags)
{
   struct agx_bo *bo;
   unsigned handle = 0;

   /* executable implies low va */
   assert(!(flags & AGX_BO_EXEC) || (flags & AGX_BO_LOW_VA));

   /* M4 instruction fetch uses the read-only GPU permission. CPU mappings
    * remain writable for uploads; shader allocations are immutable to GPU. */
   if (dev->chip == AGX_CHIP_G16G && (flags & AGX_BO_EXEC))
      flags |= AGX_BO_READONLY;

   struct drm_asahi_gem_create gem_create = {.size = size};

   if (flags & AGX_BO_WRITEBACK)
      gem_create.flags |= DRM_ASAHI_GEM_WRITEBACK;

   if (!(flags & (AGX_BO_SHARED | AGX_BO_SHAREABLE))) {
      gem_create.flags |= DRM_ASAHI_GEM_VM_PRIVATE;
      gem_create.vm_id = dev->vm_id;
   }

   int ret = drmIoctl(dev->fd, DRM_IOCTL_ASAHI_GEM_CREATE, &gem_create);
   if (ret) {
      fprintf(stderr, "DRM_IOCTL_ASAHI_GEM_CREATE failed: %m\n");
      return NULL;
   }

   handle = gem_create.handle;

   simple_mtx_lock(&dev->bo_map_lock);
   bo = agx_lookup_bo(dev, handle);
   agx_include_bo_handle(dev, handle);
   simple_mtx_unlock(&dev->bo_map_lock);

   /* Fresh handle */
   assert(!memcmp(bo, &((struct agx_bo){}), sizeof(*bo)));

   bo->dev = dev;
   bo->size = gem_create.size;
   bo->align = align;
   bo->flags = flags;
   bo->handle = bo->uapi_handle = handle;
   bo->prime_fd = -1;

   enum agx_va_flags va_flags = flags & AGX_BO_LOW_VA ? AGX_VA_USC : 0;
   bo->va = agx_va_alloc(dev, size, bo->align, va_flags, 0);
   if (!bo->va) {
      fprintf(stderr, "Failed to allocate BO VMA\n");
      agx_bo_free(dev, bo);
      return NULL;
   }

   uint32_t bind = DRM_ASAHI_BIND_READ;
   if (!(flags & AGX_BO_READONLY)) {
      bind |= DRM_ASAHI_BIND_WRITE;
   }

   ret = agx_bo_bind(dev, bo, bo->va->addr, bo->size, 0, bind);
   if (ret) {
      agx_bo_free(dev, bo);
      return NULL;
   }

   return bo;
}

static void *
agx_bo_mmap_user(struct agx_device *dev, struct agx_bo *bo, size_t size,
                  void *fixed_addr)
{
   struct drm_asahi_gem_mmap_offset gem_mmap_offset = {
      .handle = bo->uapi_handle,
   };
   if (drmIoctl(dev->fd, DRM_IOCTL_ASAHI_GEM_MMAP_OFFSET, &gem_mmap_offset))
      return NULL;

   void *map = os_mmap(fixed_addr, size, PROT_READ | PROT_WRITE,
                       MAP_SHARED | (fixed_addr ? MAP_FIXED : 0),
                       dev->fd, gem_mmap_offset.offset);
   return map == MAP_FAILED ? NULL : map;
}

static void
agx_bo_mmap(struct agx_device *dev, struct agx_bo *bo, void *fixed_addr)
{
   assert(bo->_map == NULL && "not double mapped");
   bo->_map = agx_bo_mmap_user(dev, bo, bo->size, fixed_addr);
}

struct agx_bo *
agx_bo_import(struct agx_device *dev, int fd)
{
   struct agx_bo *bo;
   ASSERTED int ret;
   unsigned gem_handle;

   simple_mtx_lock(&dev->bo_map_lock);

   ret = drmPrimeFDToHandle(dev->fd, fd, &gem_handle);
   if (ret) {
      fprintf(stderr, "import failed: Could not map fd %d to handle\n", fd);
      simple_mtx_unlock(&dev->bo_map_lock);
      return NULL;
   }

   bo = agx_lookup_bo(dev, gem_handle);
   agx_include_bo_handle(dev, gem_handle);

   if (!bo->size) {
      bo->dev = dev;
      bo->handle = gem_handle;
      bo->prime_fd = -1;
      bo->size = lseek(fd, 0, SEEK_END);
      bo->align = AIL_PAGESIZE;

      /* Sometimes this can fail and return -1. size of -1 is not
       * a nice thing for mmap to try mmap. Be more robust also
       * for zero sized maps and fail nicely too
       */
      if ((bo->size == 0) || (bo->size == (size_t)-1)) {
         goto error;
      }
      if (bo->size & (AIL_PAGESIZE - 1)) {
         fprintf(
            stderr,
            "import failed: BO is not a multiple of the page size (0x%llx bytes)\n",
            (long long)bo->size);
         goto error;
      }

      bo->flags = AGX_BO_SHARED | AGX_BO_SHAREABLE;
      bo->handle = gem_handle;
      bo->prime_fd = os_dupfd_cloexec(fd);
      bo->label = "Imported BO";
      if (bo->prime_fd < 0)
         goto error;

      p_atomic_set(&bo->refcnt, 1);
      bo->va = agx_va_alloc(dev, bo->size, bo->align, 0, 0);

      if (!bo->va) {
         fprintf(
            stderr,
            "import failed: Could not allocate from VMA heap (0x%llx bytes)\n",
            (long long)bo->size);
         goto error;
      }

      if (dev->is_virtio) {
         bo->uapi_handle = vdrm_handle_to_res_id(dev->vdrm, bo->handle);
      } else {
         bo->uapi_handle = bo->handle;
      }

      ret = agx_bo_bind(dev, bo, bo->va->addr, bo->size, 0,
                        DRM_ASAHI_BIND_READ | DRM_ASAHI_BIND_WRITE);
      if (ret) {
         fprintf(stderr, "import failed: Could not bind BO at 0x%llx\n",
                 (long long)bo->va->addr);
         goto error;
      }
   } else {
      /* bo->refcnt == 0 can happen if the BO
       * was being released but agx_bo_import() acquired the
       * lock before agx_bo_unreference(). In that case, refcnt
       * is 0 and we can't use agx_bo_reference() directly, we
       * have to re-initialize the refcnt().
       * Note that agx_bo_unreference() checks
       * refcnt value just after acquiring the lock to
       * make sure the object is not freed if agx_bo_import()
       * acquired it in the meantime.
       */
      if (p_atomic_read(&bo->refcnt) == 0)
         p_atomic_set(&bo->refcnt, 1);
      else
         agx_bo_reference(bo);

      /* If this bo came back to us via import, it had better
       * been marked shared to begin with.
       */
      assert(bo->flags & AGX_BO_SHAREABLE);
      assert(bo->flags & AGX_BO_SHARED);
      assert(bo->prime_fd != -1);
   }
   simple_mtx_unlock(&dev->bo_map_lock);

   assert(bo->dev != NULL && "post-condition");

   if (dev->debug & AGX_DBG_TRACE) {
      agx_bo_map(bo);
      agxdecode_track_alloc(dev->agxdecode, bo);
   }

   return bo;

error:
   /* Only a previously empty slot reaches here. Release every acquired
    * resource, including the new GEM handle, before dropping bo_map_lock.
    * Existing imports and the caller's dma-buf fd retain their ownership.
    */
   agx_bo_free(dev, bo);
   simple_mtx_unlock(&dev->bo_map_lock);
   return NULL;
}

void
agx_bo_make_shared(struct agx_device *dev, struct agx_bo *bo)
{
   assert(bo->flags & AGX_BO_SHAREABLE);
   if (bo->flags & AGX_BO_SHARED) {
      assert(bo->prime_fd >= 0);
      return;
   }

   bo->flags |= AGX_BO_SHARED;
   assert(bo->prime_fd == -1);

   int ret = drmPrimeHandleToFD(dev->fd, bo->handle, DRM_CLOEXEC | DRM_RDWR,
                                &bo->prime_fd);
   assert(ret == 0);
   assert(bo->prime_fd >= 0);

   /* If there is a pending writer to this BO, import it into the buffer
    * for implicit sync.
    */
   uint64_t writer = p_atomic_read_relaxed(&bo->writer);
   if (writer) {
      int out_sync_fd = -1;
      int ret = drmSyncobjExportSyncFile(dev->fd, agx_bo_writer_syncobj(writer),
                                         &out_sync_fd);
      assert(ret >= 0);
      assert(out_sync_fd >= 0);

      ret = agx_import_sync_file(dev, bo, out_sync_fd);
      assert(ret >= 0);
      close(out_sync_fd);
   }
}

int
agx_bo_export(struct agx_device *dev, struct agx_bo *bo)
{
   agx_bo_make_shared(dev, bo);

   assert(bo->prime_fd >= 0);
   return os_dupfd_cloexec(bo->prime_fd);
}

static int
agx_bo_bind_object(struct agx_device *dev,
                   struct drm_asahi_gem_bind_object *bind)
{
   int ret = drmIoctl(dev->fd, DRM_IOCTL_ASAHI_GEM_BIND_OBJECT, bind);
   if (ret) {
      fprintf(stderr,
              "DRM_IOCTL_ASAHI_GEM_BIND_OBJECT failed: %m (handle=%d)\n",
              bind->handle);
   }

   return ret;
}

static int
agx_bo_unbind_object(struct agx_device *dev, uint32_t object_handle)
{
   struct drm_asahi_gem_bind_object gem_bind = {
      .op = DRM_ASAHI_BIND_OBJECT_OP_UNBIND,
      .object_handle = object_handle,
   };

   int ret = drmIoctl(dev->fd, DRM_IOCTL_ASAHI_GEM_BIND_OBJECT, &gem_bind);
   if (ret) {
      fprintf(stderr,
              "DRM_IOCTL_ASAHI_GEM_BIND_OBJECT failed: %m (object_handle=%d)\n",
              object_handle);
   }

   return ret;
}

static ssize_t
agx_get_params(struct agx_device *dev, void *buf, size_t size)
{
   struct drm_asahi_get_params get_param = {
      .param_group = 0,
      .pointer = (uint64_t)(uintptr_t)buf,
      .size = size,
   };

   memset(buf, 0, size);

   int ret = drmIoctl(dev->fd, DRM_IOCTL_ASAHI_GET_PARAMS, &get_param);
   if (ret) {
      fprintf(stderr, "DRM_IOCTL_ASAHI_GET_PARAMS failed: %m\n");
      return -EINVAL;
   }

   return get_param.size;
}

static int
agx_submit(struct agx_device *dev, struct drm_asahi_submit *submit,
           struct agx_submit_virt *virt)
{
   return drmIoctl(dev->fd, DRM_IOCTL_ASAHI_SUBMIT, submit);
}

const agx_device_ops_t agx_device_drm_ops = {
   .bo_alloc = agx_bo_alloc,
   .bo_bind = agx_drm_bo_bind,
   .bo_mmap = agx_bo_mmap,
   .bo_mmap_user = agx_bo_mmap_user,
   .get_params = agx_get_params,
   .submit = agx_submit,
   .bo_bind_object = agx_bo_bind_object,
   .bo_unbind_object = agx_bo_unbind_object,
   .simple_ioctl = asahi_simple_ioctl,
   .bo_munmap = agx_drm_bo_munmap,
   .bo_sync_for_device = agx_drm_bo_sync_for_device,
   .bo_free = agx_drm_bo_close,
};
#else /* !HAVE_LIBDRM */
/*
 * honeykrisp-h1-execution.md SS2.1 row ":266...": dma-buf import/export
 * has no Windows equivalent in H1 (NT-handle external memory is
 * post-M-GPU-TRI, per the same row) -- these two are the only bodies from
 * the block above with call sites reachable outside HAVE_LIBDRM code
 * (hk_device_memory.c's KHR_external_memory_fd paths, whose *enabling*
 * extensions are compiled out on Windows per SS2.2 row P2, but whose C
 * bodies still call these functions unconditionally).
 */
struct agx_bo *
agx_bo_import(struct agx_device *dev, int fd)
{
   return NULL;
}

int
agx_bo_export(struct agx_device *dev, struct agx_bo *bo)
{
   return -1;
}
#endif /* HAVE_LIBDRM */

static uint64_t
gcd(uint64_t n, uint64_t m)
{
   while (n != 0) {
      uint64_t remainder = m % n;
      m = n;
      n = remainder;
   }

   return m;
}

static void
agx_init_timestamps(struct agx_device *dev)
{
   uint64_t user_ts_gcd =
      gcd(dev->params.command_timestamp_frequency_hz, NSEC_PER_SEC);

   dev->user_timestamp_to_ns.num = NSEC_PER_SEC / user_ts_gcd;
   dev->user_timestamp_to_ns.den =
      dev->params.command_timestamp_frequency_hz / user_ts_gcd;
}

static struct agx_bo *
agx_create_fixed_bo(struct agx_device *dev, size_t size,
                    enum agx_bo_flags flags, uint64_t address,
                    uint32_t bind_flags, const char *label)
{
   if (dev->ops.bo_alloc_fixed != NULL)
      return dev->ops.bo_alloc_fixed(dev, size, flags, address, bind_flags,
                                     label);

   struct agx_bo *bo = agx_bo_create(dev, size, 0, flags, label);
   if (bo == NULL)
      return NULL;

   if (agx_bo_bind(dev, bo, address, size, 0, bind_flags) != 0) {
      agx_bo_free(dev, bo);
      return NULL;
   }

   return bo;
}

bool
agx_open_device(void *memctx, struct agx_device *dev)
{
   dev->debug =
      debug_get_flags_option("ASAHI_MESA_DEBUG", agx_debug_options, 0);

   ssize_t params_size = -1;

   /*
    * honeykrisp-h1-execution.md SS2.1 row ":511-535": the DRM
    * version-probe block below is HAVE_LIBDRM/Linux-only (drmGetVersion)
    * and used to run unconditionally, clobbering any preset dev->ops.
    * agx_win_open_device() (agx_device_win.c, SS1) presets dev->ops to
    * agx_device_win_ops *before* calling this function, so skip the probe
    * whenever a backend has already been selected -- Linux/virtio callers
    * (which never preset dev->ops) are unaffected, they still take this
    * branch exactly as before.
    */
   if (dev->ops.get_params == NULL) {
#ifdef HAVE_LIBDRM
      dev->ops = agx_device_drm_ops;

      /* DRM version check */
      drmVersionPtr version = drmGetVersion(dev->fd);
      if (!version) {
         fprintf(stderr, "cannot get version: %s", strerror(errno));
         return false;
      }

      if (!strcmp(version->name, "asahi")) {
         dev->is_virtio = false;
         dev->ops = agx_device_drm_ops;
      } else if (!strcmp(version->name, "virtio_gpu")) {
         dev->is_virtio = true;
         if (!agx_virtio_open_device(dev)) {
            fprintf(
               stderr,
               "Error opening virtio-gpu device for Asahi native context\n");
            return false;
         }
      } else {
         return false;
      }

      drmFreeVersion(version);
#else
      /* No backend preset and no libdrm to probe one with -- shouldn't
       * happen: every non-HAVE_LIBDRM caller (agx_win_open_device) presets
       * dev->ops itself. */
      return false;
#endif
   }

   params_size = dev->ops.get_params(dev, &dev->params, sizeof(dev->params));
   if (params_size <= 0) {
      fprintf(stderr, "Failed to query AGX device parameters: %m\n");
      return false;
   }
   if ((size_t)params_size < sizeof(dev->params)) {
      fprintf(stderr,
              "AGX parameter reply is too short (%zd, expected at least %zu)\n",
              params_size, sizeof(dev->params));
      return false;
   }

   dev->chip = agx_chip_from_params(&dev->params);

   /*
    * Recognition, shader codegen, descriptors and the command stream are
    * independently versioned. A part is usable only once every required axis
    * is implemented; otherwise a newly-recognised chip can silently reach an
    * encoder from the wrong generation.
    */
   const bool m4_experimental = dev->chip == AGX_CHIP_G16G &&
      dev->params.chip_id == 0x8132 && dev->params.num_dies == 1 &&
      dev->params.num_clusters_total == 1 && dev->params.usc_generation == 3 &&
      dev->params.gpu_hal_generation == 200 &&
      debug_get_bool_option("ASAHI_M4_EXPERIMENTAL", false);
   const bool m3_experimental = dev->chip == AGX_CHIP_G15S &&
      dev->params.chip_id == 0x6030 && dev->params.num_dies == 1 &&
      dev->params.num_clusters_total == 2 && dev->params.usc_generation == 3 &&
      dev->params.gpu_hal_generation == 0 &&
      debug_get_bool_option("ASAHI_M3_EXPERIMENTAL", false);
   /* M3 Max (J516C): the G15C as the kernel reports it, one die of four
    * ten-core clusters, behind the same switch as the M3 Pro. */
   const bool m3max_experimental = dev->chip == AGX_CHIP_G15C &&
      dev->params.chip_id == 0x6031 && dev->params.num_dies == 1 &&
      dev->params.num_clusters_total == 4 && dev->params.usc_generation == 3 &&
      dev->params.gpu_hal_generation == 0 &&
      debug_get_bool_option("ASAHI_M3_EXPERIMENTAL", false);
   if (!m3_experimental && !m3max_experimental && !m4_experimental &&
       !agx_params_driver_supported(&dev->params)) {
      if (dev->chip == AGX_CHIP_UNKNOWN) {
         fprintf(stderr,
                 "Unsupported Apple GPU architecture G%u (variant 0x%x, %u "
                 "clusters)\n",
                 dev->params.gpu_generation, dev->params.gpu_variant,
                 dev->params.num_clusters_total);
      } else if (!agx_chip_codegen_supported(dev->chip)) {
         fprintf(stderr,
                 "Apple %s executes the %s instruction set, which this "
                 "driver has no code generator for (variant 0x%x, %u "
                 "clusters)\n",
                 agx_chip_name(dev->chip),
                 agx_isa_name(agx_chip_isa(dev->chip)),
                 dev->params.gpu_variant,
                 dev->params.num_clusters_total);
      } else if (dev->chip == AGX_CHIP_G17P) {
         fprintf(stderr,
                 "Apple G17P kernel contract does not match Honeykrisp "
                 "(USC %u, HAL %u; expected USC 3, HAL 200)\n",
                 dev->params.usc_generation,
                 dev->params.gpu_hal_generation);
      } else {
         fprintf(stderr,
                 "Apple %s uses the %s command stream, which this driver "
                 "does not implement (variant 0x%x, %u clusters)\n",
                 agx_chip_name(dev->chip),
                 agx_command_stream_generation_name(
                    agx_chip_command_stream_generation(dev->chip)),
                 dev->params.gpu_variant,
                 dev->params.num_clusters_total);
      }

#ifdef HAVE_LIBDRM
      if (dev->is_virtio) {
         vdrm_device_close(dev->vdrm);
         dev->vdrm = NULL;
      }
#endif

      return false;
   }

   const char *product = agx_chip_exact_product_name(dev->chip);
   if (product) {
      snprintf(dev->name, sizeof(dev->name), "Apple %s (G%d%c %02X)",
               product, dev->params.gpu_generation, dev->params.gpu_variant,
               dev->params.gpu_revision + 0xA0);
   } else {
      const char *variant = " Unknown";
      switch (dev->params.gpu_variant) {
      case 'G':
         variant = "";
         break;
      case 'S':
         variant = " Pro";
         break;
      case 'C':
         variant = " Max";
         break;
      case 'D':
         variant = " Ultra";
         break;
      }
      snprintf(dev->name, sizeof(dev->name), "Apple M%d%s (G%d%c %02X)",
               dev->params.gpu_generation - 12, variant,
               dev->params.gpu_generation, dev->params.gpu_variant,
               dev->params.gpu_revision + 0xA0);
   }

   /* We need a large chunk of VA space carved out for robustness. Hardware
    * loads can shift an i32 by up to 2, for a total shift of 4. If the base
    * address is zero, 36-bits is therefore enough to trap any zero-extended
    * 32-bit index. For more generality we would need a larger carveout, but
    * this is already optimal for VBOs.
    *
    * TODO: Maybe this should be on top instead? Might be ok.
    */
   uint64_t reservation = (1ull << 36);

   /* Keep the established AGX2 printf address outside the ordinary heap.
    * G17P publishes its allocator-owned address through runtime root state,
    * but retaining the same floor keeps the robustness carveout unchanged.
    */
   assert(reservation == LIBAGX_PRINTF_BUFFER_ADDRESS);
   reservation += LIBAGX_PRINTF_BUFFER_SIZE;

   dev->guard_size = AIL_PAGESIZE;

   /* Diagnostic: native Metal exposes each render write-resource group to
    * MCache as one contiguous aperture. Mesa normally reserves an unmapped
    * guard page after every BO, so a broad range spanning the live heap has
    * holes and is correctly rejected by the kernel's write-range validator.
    * Remove those holes only for the explicit G17P native-range experiment;
    * this is set before either VMA heap is initialized or any BO is created.
    */
   if (dev->chip == AGX_CHIP_G17P &&
       getenv("ASAHI_G17P_NO_GUARD") != NULL) {
      dev->guard_size = 0;
      fprintf(stderr,
              "asahi: G17P diagnostic disabled per-BO VA guard pages\n");
   }
   // Put the USC heap at the bottom of the user address space, 4GiB aligned
   dev->shader_base =
      ALIGN_POT(MAX2(dev->params.vm_start, reservation), 0x100000000ull);

   /* G17P: the USC exec window must sit at 2^40.
    *
    * HARDWARE FACT, not a preference.  With the window at the address this
    * formula derives from vm_start (0x1100000000), every Honeykrisp kick --
    * including one whose shader and preamble touch no memory at all -- ended
    * in a GMMU page fault (reason=3) with zero elapsed time, i.e. before the
    * first instruction.  With the window at 0x10000000000 the identical
    * binary executes: non-zero duration, no fault, and the shader's stores
    * land in the right buffer.  Three consecutive clients on one boot, no
    * faults.  It is also the address of the only other configuration ever
    * observed to execute on this chip, m1n1's add3 witness (CODE_IMAGE).
    *
    * Why the address matters is visible in the launch record.  The CDM
    * pipeline pointer is split across three fields: word 2 carries
    * program_va[37:6], word 1 bits 22..31 carry program_va[47:38], and word
    * 3's low byte carries program_va[47:40].  Below 2^38 the two high fields
    * are BOTH ZERO, so an entire half of the pointer encoding is never
    * exercised -- and that is exactly the regime the old base put us in.  At
    * 2^40 they carry 4 and 1, byte-identical to add3's long-standing
    * "constant" 0x01000000 and control 0x40000001.
    *
    * What is NOT the cause, each ruled out by this same experiment: the
    * offset within the window (unchanged at ~+0xfffac000 across the failing
    * and passing runs, so the window's reach is not the limit), the
    * preamble, the shader, the container, and the descriptor chain.
    *
    * The boundary IS pinned, by experiment.  A base of 0x4000000000 (2^38)
    * makes word 1 non-zero while leaving word 3's byte zero; it was run on
    * hardware and the dispatch does NOT execute (vkQueueSubmit -4, no
    * timestamps).  So "the high fields are exercised" is not the rule --
    *
    *     the program VA must have BIT 40 SET.
    *
    * Note the asymmetry this exposes: bits 38 and 39 live in the same
    * va[47:38] field as bit 40, yet setting them is not enough.  Word 3's
    * low byte carries only va[47:40], so the hardware appears to require the
    * bits that word 3 alone provides; the two fields are not the pure
    * redundancy the encoding suggests.  Anything that revisits the launch-word
    * decode, or that moves this layout again, has to explain that.
    *
    * Consequence, and it is not a conservative choice but a forced one: the
    * user heap ends up at 32GiB rather than 64GiB, because the read-only
    * sparse alias has to fit below the kernel range and the window must stay
    * a power of two.  Shrinking the kernel reservation buys nothing -- the
    * power-of-two step dominates.  32GiB of VA against <=16GB of RAM is not
    * a practical limit.
    *
    * ASAHI_G17P_USC_BASE below overrides this for further experiments only. */
   if (agx_chip_uses_hal200_ioto(dev->chip))
      dev->shader_base = AGX_G17P_USC_WINDOW_BASE;

   /* G17P launch-level bring-up controls.
    *
    * Two properties of the USC exec window have never been varied on this
    * chip, and both differ by orders of magnitude from the only configuration
    * that has ever executed a kick on it (the m1n1 add3 witness):
    *
    *   - the window BASE.  add3 uses 0x10000000000; Honeykrisp derives
    *     0x1100000000 from the kernel-reported vm_start.
    *   - the OFFSET of code within the window.  add3 places its Ioto program
    *     at base+0xa8000 and its shader container at base+0x3c0, i.e. inside
    *     the first megabyte.  util_vma_heap_init() defaults to alloc_high, so
    *     Honeykrisp places both within ~21KB of the TOP of a 4GiB window
    *     (base+0xfffac000), four orders of magnitude further out.
    *
    * The offset is the one with a documented narrow field behind it.  m1n1's
    * build_add3_preamble() (agx_g17p_native_add3.py) relocates the launch
    * header's code pointer through a 16-bit halfword counted in 0x2000-byte
    * chunks measured from usc_exec_base, and raises if the result will not fit
    * -- a reach of exactly 512MiB.  Our allocations sit 4GiB out, eight times
    * beyond it.
    *
    * Both are selected at runtime rather than compiled in so that one frozen
    * artifact covers the baseline and each experiment, and so a run's own
    * stderr records which layout produced it.  Bad values are fatal rather
    * than clamped: a silently adjusted layout would produce a result that
    * looks like an answer but is not.
    */
   const char *usc_base_env = getenv("ASAHI_G17P_USC_BASE");
   if (usc_base_env != NULL && usc_base_env[0] != '\0') {
      char *end = NULL;
      errno = 0;
      unsigned long long requested = strtoull(usc_base_env, &end, 0);

      if (errno != 0 || end == usc_base_env || *end != '\0') {
         fprintf(stderr, "ASAHI_G17P_USC_BASE=\"%s\" is not a number\n",
                 usc_base_env);
         return false;
      }

      if ((requested & 0xffffffffull) != 0) {
         fprintf(stderr,
                 "ASAHI_G17P_USC_BASE 0x%llx is not 4GiB aligned\n",
                 requested);
         return false;
      }

      dev->shader_base = requested;
   }

   if (dev->shader_base < reservation) {
      /* Our robustness implementation requires the bottom unmapped */
      fprintf(stderr, "Unexpected address layout, can't cope\n");
      assert(0);
      return false;
   }

   uint64_t shader_size = 0x100000000ull;

   /*
    * Where the user heap goes relative to the USC window.
    *
    * Everywhere else the heap follows the USC window, which is what the
    * original layout did. G17P cannot: its USC window sits at exactly 2^40,
    * so a heap placed after it starts above 2^40 -- and the VDM PPP State
    * Update carries its payload pointer in a FORTY BIT field (word 0 bits
    * 0..7 hold pointer bits 32..39; see agx_vdm_ppp_state_core.h, which reads
    * that layout off Apple's own G15/HAL200/HAL300 emitters). Every PPP
    * payload was therefore unaddressable, agx_ppp_fini() refused it, and
    * vkEndCommandBuffer returned VK_ERROR_FEATURE_NOT_PRESENT before a render
    * command buffer could ever be recorded.
    *
    * Compute never noticed because nothing on that path encodes a 40-bit
    * pointer.
    *
    * The VDM control-stream register is narrower still: G17P interprets its
    * value as a 39-bit offset from 0x1000000000. Therefore both the primary
    * heap and its sparse shadow must end by 0x9000000000, not merely below
    * the 2^40 USC window. This leaves the bottom 2^36 robustness carveout
    * untouched while making every ordinary control-stream allocation
    * directly representable, with no per-run alias option.
    */
   const bool heap_below_usc = agx_chip_uses_hal200_ioto(dev->chip);

   /*
    * Start the low heap as high as it can go rather than at the reservation.
    * agx_va_split_user_window() requires size < start and the sparse alias
    * needs a second window of the same size, so the usable heap is maximised
    * by start = shader_base/2: that yields size = shader_base/4 with the alias
    * ending exactly at shader_base. Starting at the reservation instead would
    * waste three quarters of the range on unused low VA.
    */
   uint64_t low_floor =
      ALIGN_POT(MAX2(dev->params.vm_start, reservation), 0x100000000ull);
   uint64_t user_start;
   if (heap_below_usc) {
      user_start = MAX2(low_floor, dev->shader_base / 2);
   } else {
      user_start = dev->shader_base + shader_size;
   }

   /* Checked rather than asserted: the base is settable at runtime and these
    * are release builds. */
   if (dev->shader_base < dev->params.vm_start ||
       (!heap_below_usc && user_start <= dev->shader_base) ||
       (heap_below_usc && user_start >= dev->shader_base) ||
       user_start >= dev->params.vm_end) {
      fprintf(stderr,
              "USC window [%#llx, %#llx) does not fit the kernel VA window "
              "[%#llx, %#llx)\n",
              (unsigned long long)dev->shader_base,
              (unsigned long long)user_start,
              (unsigned long long)dev->params.vm_start,
              (unsigned long long)dev->params.vm_end);
      return false;
   }

   // Put the kernel heap at the top of the address space.
   // Give it 32GB of address space, should be more than enough for any
   // reasonable use case.
   uint64_t kernel_size = MAX2(dev->params.vm_kernel_min_size, 32ull << 30);
   struct drm_asahi_vm_create vm_create = {
      .kernel_start = dev->params.vm_end - kernel_size,
      .kernel_end = dev->params.vm_end,
   };

   /* G17P is bounded by the compact VDM aperture, which is below the USC
    * window. Other chips retain the kernel-reported user limit. */
   const uint64_t user_limit =
      heap_below_usc ? AGX_G17P_VDM_USER_LIMIT : vm_create.kernel_start;
   uint64_t user_size = user_limit - user_start;

   int ret = dev->ops.simple_ioctl(dev, DRM_IOCTL_ASAHI_VM_CREATE, &vm_create);
   if (ret) {
      fprintf(stderr, "DRM_IOCTL_ASAHI_VM_CREATE failed: %m\n");
      return false;
   }

   dev->agxdecode = agxdecode_new_context(dev->shader_base);

   agx_init_timestamps(dev);

   util_sparse_array_init(&dev->bo_map, sizeof(struct agx_bo), 512);
   simple_mtx_init(&dev->bo_map_lock, mtx_plain);

   simple_mtx_init(&dev->bo_cache.lock, mtx_plain);
   list_inithead(&dev->bo_cache.lru);
   dev->bo_cache.trim_generation = 1;

   for (unsigned i = 0; i < ARRAY_SIZE(dev->bo_cache.buckets); ++i)
      list_inithead(&dev->bo_cache.buckets[i]);

   /* Round the user VA window to a power-of-two window whose top half can be
    * addressed by a single bit, so sparse buffers can be aliased read-only at
    * +sparse_ro_offset.  This is a hard failure rather than an assert: the
    * reduction depends on the kernel-reported window, so a geometry we cannot
    * split must be reported, not tripped over in a debug build and silently
    * miscomputed in a release one.
    */
   if (!agx_va_split_user_window(user_start, user_size, &user_start,
                                 &user_size)) {
      fprintf(stderr,
              "Cannot split the kernel user VA window [%#llx, %#llx) for "
              "sparse aliasing\n",
              (unsigned long long)dev->params.vm_start,
              (unsigned long long)dev->params.vm_end);
      return false;
   }

   /* Every vkAllocateMemory() binds a read-only shadow of the allocation at
    * +sparse_ro_offset, unconditionally, "in case this is used for a sparse
    * resident buffer" (hk_device_memory.c).  So the ALIAS window
    * [user_start + user_size, user_start + 2 * user_size) is live for every
    * app allocation, not just sparse ones, and the kernel rejects a bind that
    * leaves the user range or touches the kernel range (file.rs gem_bind:
    * "not contained in user range" / "intrudes in kernel range", both EINVAL).
    *
    * agx_va_split_user_window() only sizes the window against its own start;
    * it never sees kernel_start, so nothing has been checking that the alias
    * half still fits underneath it.  At the default base it fits with three
    * orders of magnitude to spare, which is why this has never fired.  Move
    * the USC window to 2^40 and the split yields a 1TiB user heap at
    * 0x20000000000 whose alias reaches 0x40000000000 -- past the top of the
    * user range and straight through the kernel's 32GiB reservation -- and
    * the FIRST app allocation fails with VK_ERROR_UNKNOWN before anything is
    * ever submitted.
    *
    * Halve until the alias fits.  This is a no-op for the default layout
    * (0x2000000000 + 2 * 0x1000000000 = 0x4000000000, far below a kernel
    * range starting at 0x3f7fff_f8000), so it does not perturb the baseline. */
   while (user_size > 0 && user_start + 2 * user_size > user_limit)
      user_size /= 2;

   if (user_size == 0) {
      fprintf(stderr,
              "User VA window at %#llx leaves no room for the sparse "
              "read-only alias below %#llx\n",
              (unsigned long long)user_start,
              (unsigned long long)user_limit);
      return false;
   }

   dev->sparse_ro_offset = user_size;
   dev->main_heap_base = user_start;
   dev->main_heap_size = user_size;

   simple_mtx_init(&dev->vma_lock, mtx_plain);
   util_vma_heap_init(&dev->main_heap, user_start, user_size);
   util_vma_heap_init(&dev->usc_heap, dev->shader_base, shader_size);

   /* Capture/replay buffers replay their captured addresses with fixed VA
    * allocations. Placing them in the shared heap let an ordinary allocation
    * made between capture and replay occupy a captured range
    * (binding_model.buffer_device_address.capture_replay_stress.seed_3 failed
    * with "Sparse VMA allocation failed"). Reserve a region for them. */
   {
      const uint64_t replay_size = MIN2(user_size / 8, 64ull << 30);
      const uint64_t replay_base =
         replay_size >= (1ull << 30)
            ? util_vma_heap_alloc(&dev->main_heap, replay_size, 1ull << 30)
            : 0;
      if (replay_base)
         util_vma_heap_init(&dev->replay_heap, replay_base, replay_size);
      else
         memset(&dev->replay_heap, 0, sizeof(dev->replay_heap));
   }
   if (agx_native_graphics(dev) &&
       !agx_g17p_vdm_alias_heap_init(&dev->g17p_vdm_alias_heap)) {
      fprintf(stderr, "Failed to initialize G17P low VDM alias heap\n");
      return false;
   }

   /* The M3 owned parameter pool and render graph occupy the first 128 MiB.
    * Reserve the portion above the common 8 MiB alias start before allocating
    * command streams, matching m3_runtime::new_vm. */
   if (dev->chip == AGX_CHIP_G15S &&
       !util_vma_heap_alloc_addr(&dev->g17p_vdm_alias_heap,
                                AGX_G17P_VDM_ALIAS_BASE,
                                UINT64_C(0x08000000) - AGX_G17P_VDM_ALIAS_OFFSET_START)) {
      fprintf(stderr, "Failed to reserve M3 render graph aperture\n");
      return false;
   }

   /* Experimental M3 owns a fixed parameter-page list in this aperture. */
   if (dev->chip == AGX_CHIP_G15S &&
       !util_vma_heap_alloc_addr(&dev->g17p_vdm_alias_heap,
                                UINT64_C(0x1074000000), 0x28000)) {
      fprintf(stderr, "Failed to reserve M3 parameter page list\n");
      return false;
   }

   /* util_vma_heap_init() defaults to alloc_high, which puts every shader and
    * Ioto program within a few pages of the TOP of the 4GiB USC window.  The
    * only G17P configuration ever observed to execute keeps its code inside
    * the first megabyte of the window; see the note on the base above.  This
    * makes the direction selectable so that difference can be tested on its
    * own.  It only reverses a search order -- no address is computed from it
    * -- so an unrecognised value simply keeps the upstream default. */
   const char *usc_low_env = getenv("ASAHI_G17P_USC_LOW");
   const bool usc_low = usc_low_env != NULL && usc_low_env[0] == '1' &&
                        usc_low_env[1] == '\0';
   if (usc_low || dev->chip == AGX_CHIP_G16G || dev->chip == AGX_CHIP_G15S)
      dev->usc_heap.alloc_high = false;

   if (dev->chip == AGX_CHIP_G17P) {
      fprintf(stderr,
              "asahi: G17P USC window base %#llx size %#llx alloc=%s; "
              "user heap %#llx size %#llx\n",
              (unsigned long long)dev->shader_base,
              (unsigned long long)shader_size, usc_low ? "low" : "high",
              (unsigned long long)user_start, (unsigned long long)user_size);
   }

   if (!agx_va_reserve_runtime_graph_hole(
          dev->chip, &dev->main_heap, user_start, user_size,
          dev->sparse_ro_offset, &dev->usc_heap, dev->shader_base,
          shader_size)) {
      fprintf(stderr, "Failed to reserve firmware runtime-graph GPU VA\n");
      return false;
   }

   if (dev->ops.va_init != NULL &&
       !dev->ops.va_init(dev, user_start, user_size, dev->shader_base,
                         shader_size)) {
      fprintf(stderr, "Failed to initialize process GPU VA allocator\n");
      return false;
   }

   dev->vm_id = vm_create.vm_id;

   glsl_type_singleton_init_or_ref();

   if (agx_chip_uses_legacy_precompiled_programs(dev->chip)) {
      if (agx_gather_device_key(dev).needs_g13x_coherency == U_TRISTATE_YES)
         dev->libagx_programs = libagx_g13x;
      else
         dev->libagx_programs = libagx_g13g;
   } else {
      dev->libagx_programs = NULL;
   }

   /* Bind read-only zero page at 2^32. This is in our reservation, and can be
    * addressed with only small integers in the low/high. That lets us do some
    * robustness optimization even without soft fault.
    */
   {
      struct agx_bo *bo =
         agx_create_fixed_bo(dev, AGX_ZERO_PAGE_SIZE, 0, AGX_ZERO_PAGE_ADDRESS,
                             DRM_ASAHI_BIND_READ, "Zero page");
      if (bo == NULL) {
         fprintf(stderr, "Failed to bind zero page");
         return false;
      }

      dev->zero_bo = bo;
   }

   {
      struct agx_bo *bo = agx_create_fixed_bo(
         dev, AIL_PAGESIZE, 0, AGX_SCRATCH_PAGE_ADDRESS,
         DRM_ASAHI_BIND_READ | DRM_ASAHI_BIND_WRITE, "Scratch page");
      if (bo == NULL) {
         fprintf(stderr, "Failed to bind scratch page");
         return false;
      }

      dev->scratch_bo = bo;

      /* The contents of the scratch page are undefined, but making them nonzero
       * helps fuzz for bugs where we incorrectly read from the write section.
       */
      memset(agx_bo_map(dev->scratch_bo), 0xCA, AIL_PAGESIZE);
   }

   if (dev->chip == AGX_CHIP_G17P) {
      struct agx_bo *context = agx_create_fixed_bo(
         dev, AGX_G17P_RENDER_CONTEXT_SIZE, AGX_BO_WRITEBACK,
         AGX_G17P_RENDER_CONTEXT_BASE,
         DRM_ASAHI_BIND_READ | DRM_ASAHI_BIND_WRITE,
         "G17P native render context");
      if (context == NULL) {
         fprintf(stderr, "Failed to bind G17P native render context");
         return false;
      }

      void *context_map = agx_bo_map(context);
      if (context_map == NULL) {
         fprintf(stderr, "Failed to map G17P native render context");
         return false;
      }
      memset(context_map, 0, AGX_G17P_RENDER_CONTEXT_SIZE);
      /* Publish fixed Bind0 exactly once, before any command buffer can
       * reference this context. Mutable PPP payloads use retained uploads. */
      if (!agx_g17p_bind0_initialize(context_map, AGX_G17P_RENDER_CONTEXT_SIZE))
         return false;
      if (agx_bo_sync_for_device(context, 0, AGX_G17P_RENDER_CONTEXT_SIZE))
         return false;

      if (!agx_g17p_bind_render_context_low_slots(dev, context)) {
         agx_bo_unreference(dev, context);
         return false;
      }

      dev->g17p_render_context_bo = context;
   }

   struct agx_bo *bo =
      agx_native_graphics(dev)
         ? agx_bo_create(dev, LIBAGX_PRINTF_BUFFER_SIZE, 0, AGX_BO_WRITEBACK,
                         "Printf/abort")
         : agx_create_fixed_bo(
              dev, LIBAGX_PRINTF_BUFFER_SIZE, AGX_BO_WRITEBACK,
              LIBAGX_PRINTF_BUFFER_ADDRESS,
              DRM_ASAHI_BIND_READ | DRM_ASAHI_BIND_WRITE, "Printf/abort");
   if (bo == NULL) {
      fprintf(stderr, "Failed to bind printf buffer");
      return false;
   }

   if (dev->chip == AGX_CHIP_G17P &&
       (bo->va == NULL || dev->main_heap_size < LIBAGX_PRINTF_BUFFER_SIZE ||
        bo->va->addr < dev->main_heap_base ||
        bo->va->addr - dev->main_heap_base >
           dev->main_heap_size - LIBAGX_PRINTF_BUFFER_SIZE)) {
      fprintf(stderr, "G17P printf buffer escaped the allocator-owned heap");
      agx_bo_unreference(dev, bo);
      return false;
   }

   dev->printf_buffer_address =
      agx_native_graphics(dev) ? bo->va->addr
                                 : LIBAGX_PRINTF_BUFFER_ADDRESS;

   u_printf_init(&dev->printf, bo, agx_bo_map(bo));

   /* G17P: make the USC exec window's base page resident.
    *
    * The kernel programs dev->shader_base into USC_EXEC_BASE_CP for every
    * command on the queue, so that register always names a real address to
    * the hardware.  In every m1n1 witness that address is the base of the
    * code container and is mapped; in Honeykrisp it was the bottom of a
    * top-down heap and was mapped by nothing, which the kernel audit confirms
    * on hardware ("usc_exec_base 0x1100000000+0x4000 covered=false phys=0x0").
    * That is the last structural difference left between a passing add3 kick
    * and a failing Honeykrisp one.
    *
    * The page carries the container's fixed leading block -- the same bytes
    * both captured Apple code images start with -- and its own block-size
    * dword terminates the chain, so it is a well-formed empty container
    * rather than a blank page.
    */
   if (agx_chip_uses_hal200_ioto(dev->chip)) {
      const size_t usc_base_size = AIL_PAGESIZE;

      simple_mtx_lock(&dev->vma_lock);
      bool reserved = util_vma_heap_alloc_addr(&dev->usc_heap, dev->shader_base,
                                               usc_base_size + dev->guard_size);
      simple_mtx_unlock(&dev->vma_lock);

      if (!reserved) {
         fprintf(stderr, "Failed to reserve the USC window base page\n");
         return false;
      }

      struct agx_bo *usc_base = agx_create_fixed_bo(
         dev, usc_base_size, (dev->chip == AGX_CHIP_G16G || dev->chip == AGX_CHIP_G15S) ? 0 : AGX_BO_WRITEBACK, dev->shader_base,
         DRM_ASAHI_BIND_READ, "HAL200 USC window base");
      if (usc_base == NULL) {
         fprintf(stderr, "Failed to bind the USC window base page\n");
         return false;
      }

      void *map = agx_bo_map(usc_base);
      if (map == NULL) {
         fprintf(stderr, "Failed to map the USC window base page\n");
         return false;
      }

      memset(map, 0, usc_base_size);
      agx3_build_container_lead_for_chip(map, dev->chip);
      if (agx_bo_sync_for_device(usc_base, 0, usc_base_size))
         return false;

      dev->usc_base_bo = usc_base;
   }

   return true;
}

void
agx_close_device(struct agx_device *dev)
{
   agx_bo_unreference(dev, dev->printf.bo);
   agx_bo_unreference(dev, dev->usc_base_bo);
   if (dev->g17p_render_context_bo) {
      agx_g17p_unbind_render_context_low_slots(
         dev, ARRAY_SIZE(agx_g17p_render_context_low_slots));
   }
   agx_bo_unreference(dev, dev->g17p_render_context_bo);
   agx_bo_unreference(dev, dev->zero_bo);
   agx_bo_unreference(dev, dev->scratch_bo);
   u_printf_destroy(&dev->printf);
   agx_bo_cache_evict_all(dev);
   util_sparse_array_finish(&dev->bo_map);
   agxdecode_destroy_context(dev->agxdecode);

   if (dev->replay_heap.free_size)
      util_vma_heap_finish(&dev->replay_heap);
   util_vma_heap_finish(&dev->main_heap);
   util_vma_heap_finish(&dev->usc_heap);
   if (agx_native_graphics(dev))
      util_vma_heap_finish(&dev->g17p_vdm_alias_heap);
   glsl_type_singleton_decref();

   /* Non-DRM winsyses own their platform handles and tear them down after
    * the common BO caches and VMA heaps have been finalized here. */
#ifdef _WIN32
   if (dev->ops.simple_ioctl == agx_device_d3dkmt_ops.simple_ioctl)
      agx_d3dkmt_close_device(dev);
#else
   close(dev->fd);
#endif
}

uint32_t
agx_create_command_queue(struct agx_device *dev,
                         enum drm_asahi_priority priority)
{

   if (dev->debug & AGX_DBG_1QUEUE) {
      // Abuse this lock for this, it's debug only anyway
      simple_mtx_lock(&dev->vma_lock);
      if (dev->queue_id) {
         simple_mtx_unlock(&dev->vma_lock);
         return dev->queue_id;
      }
   }

   struct drm_asahi_queue_create queue_create = {
      .vm_id = dev->vm_id,
      .priority = priority,
      .usc_exec_base = dev->shader_base,
   };

   int ret =
      dev->ops.simple_ioctl(dev, DRM_IOCTL_ASAHI_QUEUE_CREATE, &queue_create);
   if (ret) {
      int saved_errno = errno;
      if (dev->debug & AGX_DBG_1QUEUE)
         simple_mtx_unlock(&dev->vma_lock);
      errno = saved_errno;
      return UINT32_MAX;
   }

   if (dev->debug & AGX_DBG_1QUEUE) {
      dev->queue_id = queue_create.queue_id;
      simple_mtx_unlock(&dev->vma_lock);
   }

   return queue_create.queue_id;
}

int
agx_destroy_command_queue(struct agx_device *dev, uint32_t queue_id)
{
   if (dev->debug & AGX_DBG_1QUEUE)
      return 0;

   struct drm_asahi_queue_destroy queue_destroy = {
      .queue_id = queue_id,
   };

   return dev->ops.simple_ioctl(dev, DRM_IOCTL_ASAHI_QUEUE_DESTROY,
                                &queue_destroy);
}

/*
 * honeykrisp-h1-execution.md SS2.1 row ":803, :820": dma-buf ioctls, only
 * reachable from agx_bo_make_shared (itself HAVE_LIBDRM-only above) and
 * Linux WSI implicit sync -- never taken with the win32 WSI backend (SS4).
 */
#ifdef HAVE_LIBDRM
int
agx_import_sync_file(struct agx_device *dev, struct agx_bo *bo, int fd)
{
   struct dma_buf_import_sync_file import_sync_file_ioctl = {
      .flags = DMA_BUF_SYNC_WRITE,
      .fd = fd,
   };

   assert(fd >= 0);
   assert(bo->prime_fd != -1);

   int ret = drmIoctl(bo->prime_fd, DMA_BUF_IOCTL_IMPORT_SYNC_FILE,
                      &import_sync_file_ioctl);
   assert(ret >= 0);

   return ret;
}

int
agx_export_sync_file(struct agx_device *dev, struct agx_bo *bo)
{
   struct dma_buf_export_sync_file export_sync_file_ioctl = {
      .flags = DMA_BUF_SYNC_RW,
      .fd = -1,
   };

   assert(bo->prime_fd != -1);

   int ret = drmIoctl(bo->prime_fd, DMA_BUF_IOCTL_EXPORT_SYNC_FILE,
                      &export_sync_file_ioctl);
   assert(ret >= 0);
   assert(export_sync_file_ioctl.fd >= 0);

   return ret >= 0 ? export_sync_file_ioctl.fd : ret;
}
#endif /* HAVE_LIBDRM */

void
agx_debug_fault(struct agx_device *dev, uint64_t addr)
{
   simple_mtx_lock(&dev->bo_map_lock);

   struct agx_bo *best = NULL;

   for (uint32_t handle = 0; handle < dev->max_handle; handle++) {
      struct agx_bo *bo = agx_lookup_bo(dev, handle);
      if (!bo->va)
         continue;

      /* VMA heap addresses are absolute. AGX_BO_LOW_VA selects the USC
       * heap; agx_usc_addr() is the only layer that converts one to a
       * shader-base-relative packed pointer. */
      uint64_t bo_addr = bo->va->addr;

      if (!bo->size || bo_addr > addr)
         continue;

      if (!best || bo_addr > best->va->addr)
         best = bo;
   }

   if (!best) {
      mesa_logw("Address 0x%" PRIx64 " is unknown\n", addr);
   } else {
      uint64_t start = best->va->addr;
      uint64_t end = best->va->addr + best->size;
      if (addr > (end + 1024 * 1024 * 1024)) {
         /* 1GiB max as a sanity check */
         mesa_logw("Address 0x%" PRIx64 " is unknown\n", addr);
      } else if (addr > end) {
         mesa_logw("Address 0x%" PRIx64 " is 0x%" PRIx64
                   " bytes beyond an object at 0x%" PRIx64 "..0x%" PRIx64
                   " (%s)\n",
                   addr, addr - end, start, end - 1, best->label);
      } else {
         mesa_logw("Address 0x%" PRIx64 " is 0x%" PRIx64
                   " bytes into an object at 0x%" PRIx64 "..0x%" PRIx64
                   " (%s)\n",
                   addr, addr - start, start, end - 1, best->label);
      }
   }

   simple_mtx_unlock(&dev->bo_map_lock);
}

uint64_t
agx_get_gpu_timestamp(struct agx_device *dev)
{
   struct drm_asahi_get_time get_time = {.flags = 0};

   int ret = dev->ops.simple_ioctl(dev, DRM_IOCTL_ASAHI_GET_TIME, &get_time);
   if (ret) {
      fprintf(stderr, "DRM_IOCTL_ASAHI_GET_TIME failed: %m\n");
   }

   return get_time.gpu_timestamp;
}

/* (Re)define UUID_SIZE to avoid including vulkan.h (or p_defines.h) here. */
#define UUID_SIZE 16

void
agx_get_device_uuid(const struct agx_device *dev, void *uuid)
{
   blake3_hasher blake3_ctx;
   _mesa_blake3_init(&blake3_ctx);

   /* The device UUID uniquely identifies the given device within the machine.
    * Since we never have more than one device, this doesn't need to be a real
    * UUID, so we use BLAKE3("agx" + gpu_generation + gpu_variant + gpu_revision).
    */
   static const char *device_name = "agx";
   _mesa_blake3_update(&blake3_ctx, device_name, strlen(device_name));

   _mesa_blake3_update(&blake3_ctx, &dev->params.gpu_generation,
                     sizeof(dev->params.gpu_generation));
   _mesa_blake3_update(&blake3_ctx, &dev->params.gpu_variant,
                     sizeof(dev->params.gpu_variant));
   _mesa_blake3_update(&blake3_ctx, &dev->params.gpu_revision,
                     sizeof(dev->params.gpu_revision));

   uint8_t blake3[BLAKE3_KEY_LEN];
   _mesa_blake3_final(&blake3_ctx, blake3);

   assert(BLAKE3_KEY_LEN >= UUID_SIZE);
   memcpy(uuid, blake3, UUID_SIZE);
}

void
agx_get_driver_uuid(void *uuid)
{
   const char *driver_id = PACKAGE_VERSION MESA_GIT_SHA1;

   /* The driver UUID is used for determining sharability of images and memory
    * between two Vulkan instances in separate processes, but also to
    * determining memory objects and sharability between Vulkan and OpenGL
    * driver. People who want to share memory need to also check the device
    * UUID.
    */
   blake3_hasher blake3_ctx;
   _mesa_blake3_init(&blake3_ctx);

   _mesa_blake3_update(&blake3_ctx, driver_id, strlen(driver_id));

   uint8_t blake3[BLAKE3_KEY_LEN];
   _mesa_blake3_final(&blake3_ctx, blake3);

   assert(BLAKE3_KEY_LEN >= UUID_SIZE);
   memcpy(uuid, blake3, UUID_SIZE);
}

unsigned
agx_get_num_cores(const struct agx_device *dev)
{
   unsigned n = 0;

   for (unsigned cl = 0; cl < dev->params.num_clusters_total; cl++) {
      n += util_bitcount(dev->params.core_masks[cl]);
   }

   return n;
}

struct agx_device_key
agx_gather_device_key(struct agx_device *dev)
{
   bool g13x_coh = (dev->params.gpu_generation == 13 &&
                    dev->params.num_clusters_total > 1) ||
                   dev->params.num_dies > 1;

   return (struct agx_device_key){
      .encoding = agx_chip_isa_encoding(dev->chip),
      .needs_g13x_coherency = u_tristate_make(g13x_coh),
      .soft_fault = agx_has_soft_fault(dev),
   };
}
