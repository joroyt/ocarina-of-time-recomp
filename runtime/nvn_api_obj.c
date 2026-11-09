// From metroid-prime-4-recomp runtime/nvn_api_obj.c @ 586e91e1b6f38c9e512e39f2d47a046fdf273cf0 (MIT, Copyright (c) 2026 Jeff Aigner), copied with mp4 renamed to oot; nvnProgramInitializeFromBuilder (NVN2).
// From fe3h-pc-recomp runtime/nvn_api_obj.c @ 47ef99126793dbd13e4a475feb910a13ef6639b8 (MIT, Copyright (c) 2026 Jeff Aigner), copied with fe3h renamed to mp4 only; adds the sparse tile layout queries; WindowAcquireTexture waits for the GPU's completion of the image's last present.
// From totk-pc-recomp runtime/nvn_api_obj.c @ c944f9f94520874f2a669add30dd08d29ee9f7b5 (MIT, Copyright (c) 2026 Valiantsin Dzerakh); renamed to fe3h; tracks the live windows for nvn_window_uses_pool (FE3H frees a pool per loaded resource); texture and sampler ids are slots of their pool (FE3H uses several pools).
// NVN front end, second slice: descriptor pools, textures, samplers, programs,
// windows with present pacing, and the state objects. Ported from MacNativeGames
// games/totk/third_party/d2r_gfx/gfx/nvn/hle_nvn.c @ b75be8cf (MIT, Copyright (c) 2026 jhaizhou; origin d2r-mobile),
// lines 254-535, 1775-1829, 2070-2215 and 2579-2727, and nvn_pace.h; Metal, mach, the translation thread, frame
// interpolation and Apple diagnostics dropped. Calls that reached Metal go to gfx_backend() (gfx.h).
//
// Objects are stored in place in the NVN object memory the game provides (nvn_obj.h); every argument is read from the
// AAPCS64 registers (host.h arg_x / arg_s / arg_p) and every result returned with ret_x. Command-buffer procs are in
// nvn_api_cmd.c, the TOTK extension procs in nvn_ext.c.
#include <windows.h>
#include <stdint.h>
#include <stdlib.h>
#include <stdio.h>
#include <string.h>

#include "gfx.h"
#include "cfg.h"
#include "host.h"
#include "nvn_api.h"
#include "nvn_hmap.h"
#include "platform/platform.h"
#include "nvn_tex.h"

// ---------- Descriptor pools
// An NVN texture or sampler id indexes the pool bound with SetTexturePool / SetSamplerPool; the back end keeps one slot
// table of each kind. TotK registers into one pool of each kind; FE3H uses several (its 2D layer and its 3D renderer)
// whose ids overlap, so a slot is the pool's base plus the id: the first pool seen keeps base 0, every further pool
// starts after the sizes of those before it. A pool is known by its descriptor memory (memory pool and offset), which
// outlives the NVNtexturePool object the game may initialize again there. Registration (below) and the binds the
// replay applies (vk_exec_draw.c bind_handles) translate the same way.
typedef struct { uintptr_t key; int base, n; } DpoolBase;
static DpoolBase g_tpools[16], g_spools[16];
static int g_ntpools, g_nspools;
static SRWLOCK g_dpool_lock = SRWLOCK_INIT;

static int dpool_slot(DpoolBase *tab, int *count, int limit, const dpool_t *p, int id, const char *what) {
    if (!p || !p->pool) return id;
    uintptr_t key = (uintptr_t)p->pool->mem + (uintptr_t)p->off;
    AcquireSRWLockExclusive(&g_dpool_lock);
    int base = -1;
    for (int i = 0; i < *count && base < 0; i++)
        if (tab[i].key == key) base = tab[i].base;
    if (base < 0) {
        if (*count == 16) rt_fatal("nvn: more than 16 %s pools", what);
        base = *count ? tab[*count - 1].base + tab[*count - 1].n : 0;
        if (base + p->n > limit)
            rt_fatal("nvn: %s pool %d of %d descriptors at base %d: beyond the %d slots a handle can name", what, *count,
                     p->n, base, limit);
        tab[(*count)++] = (DpoolBase){key, base, p->n};
        NVN_LOG("%s pool %d: %d descriptors at slot base %d", what, *count - 1, p->n, base);
    }
    ReleaseSRWLockExclusive(&g_dpool_lock);
    return base + id;
}
int nvn_tpool_slot(const dpool_t *p, int id) { return dpool_slot(g_tpools, &g_ntpools, 1 << 20, p, id, "texture"); }
int nvn_spool_slot(const dpool_t *p, int id) { return dpool_slot(g_spools, &g_nspools, 1 << 20, p, id, "sampler"); }

// NVNboolean nvnTexturePoolInitialize(NVNtexturePool *tp, const NVNmemoryPool *p, ptrdiff_t offset, int n)
NVN_API(nvnTexturePoolInitialize) {
    *(dpool_t *)arg_p(c, 0) = (dpool_t){arg_p(c, 1), (int64_t)arg_x(c, 2), (int32_t)arg_x(c, 3)};
    NVN_LOG("TexturePool n=%d", (int)arg_x(c, 3));
    ret_x(c, 1);
}
// void nvnTexturePoolFinalize(NVNtexturePool *tp)
NVN_API(nvnTexturePoolFinalize) { (void)c; }
// void nvnTexturePoolRegisterTexture(const NVNtexturePool *tp, int id, const NVNtexture *t, const NVNtextureView *v)
NVN_API(nvnTexturePoolRegisterTexture) {
    gfx_backend()->texture_register(nvn_tpool_slot(arg_p(c, 0), (int)arg_x(c, 1)), arg_p(c, 2), arg_p(c, 3));
}
// NVNboolean nvnSamplerPoolInitialize(NVNsamplerPool *sp, const NVNmemoryPool *p, ptrdiff_t offset, int n)
NVN_API(nvnSamplerPoolInitialize) {
    *(dpool_t *)arg_p(c, 0) = (dpool_t){arg_p(c, 1), (int64_t)arg_x(c, 2), (int32_t)arg_x(c, 3)};
    NVN_LOG("SamplerPool n=%d", (int)arg_x(c, 3));
    ret_x(c, 1);
}
// void nvnSamplerPoolFinalize(NVNsamplerPool *sp)
NVN_API(nvnSamplerPoolFinalize) { (void)c; }
// void nvnSamplerPoolRegisterSampler(const NVNsamplerPool *sp, int id, const NVNsampler *s)
NVN_API(nvnSamplerPoolRegisterSampler) {
    gfx_backend()->sampler_register(nvn_spool_slot(arg_p(c, 0), (int)arg_x(c, 1)), &((const samp_t *)arg_p(c, 2))->p);
}

// ---------- Texture builder
#define TB(c) ((tex_builder_t *)arg_p(c, 0))
// void nvnTextureBuilderSetDefaults(NVNtextureBuilder *b): keeps the device
NVN_API(nvnTextureBuilderSetDefaults) {
    tex_builder_t *b = TB(c);
    NVNdevice *dev = b->dev;
    memset(b, 0, sizeof *b);
    b->dev = dev;
    b->d.swizzle_r = 2;
    b->d.swizzle_g = 3;
    b->d.swizzle_b = 4;
    b->d.swizzle_a = 5;
    b->d.target = NVN_TEXTURE_TARGET_2D;
    b->d.width = b->d.height = b->d.depth = b->d.levels = 1;
}
NVN_API(nvnTextureBuilderSetDevice) { TB(c)->dev = arg_p(c, 1); }
NVN_API(nvnTextureBuilderSetFlags) { TB(c)->d.flags = (int)arg_x(c, 1); }
NVN_API(nvnTextureBuilderSetTarget) { TB(c)->d.target = (int)arg_x(c, 1); }
NVN_API(nvnTextureBuilderSetWidth) { TB(c)->d.width = (uint32_t)arg_x(c, 1); }
NVN_API(nvnTextureBuilderSetHeight) { TB(c)->d.height = (uint32_t)arg_x(c, 1); }
NVN_API(nvnTextureBuilderSetDepth) { TB(c)->d.depth = (uint32_t)arg_x(c, 1); }
NVN_API(nvnTextureBuilderSetSize1D) {
    tex_builder_t *b = TB(c);
    b->d.width = (uint32_t)arg_x(c, 1);
    b->d.height = b->d.depth = 1;
}
NVN_API(nvnTextureBuilderSetSize2D) {
    tex_builder_t *b = TB(c);
    b->d.width = (uint32_t)arg_x(c, 1);
    b->d.height = (uint32_t)arg_x(c, 2);
    b->d.depth = 1;
}
NVN_API(nvnTextureBuilderSetSize3D) {
    tex_builder_t *b = TB(c);
    b->d.width = (uint32_t)arg_x(c, 1);
    b->d.height = (uint32_t)arg_x(c, 2);
    b->d.depth = (uint32_t)arg_x(c, 3);
}
NVN_API(nvnTextureBuilderSetLevels) { TB(c)->d.levels = (uint32_t)arg_x(c, 1); }
NVN_API(nvnTextureBuilderSetFormat) { TB(c)->d.format = (int)arg_x(c, 1); }
// The back end samples the depth plane; stencil-plane sampling stops.
NVN_API(nvnTextureBuilderSetDepthStencilMode) {
    if ((uint32_t)arg_x(c, 1) != NVN_TEXTURE_DEPTH_STENCIL_MODE_DEPTH)
        rt_fatal("nvn: stencil-plane texture sampling is not implemented");
}
NVN_API(nvnTextureBuilderSetSwizzle) {
    uint32_t s[4] = {(uint32_t)arg_x(c, 1), (uint32_t)arg_x(c, 2), (uint32_t)arg_x(c, 3), (uint32_t)arg_x(c, 4)};
    for (int i = 0; i < 4; i++)
        if (s[i] > 5) rt_fatal("nvn: invalid texture swizzle %u", s[i]);
    nvn_texdesc *d = &TB(c)->d;
    d->swizzle_r = s[0];
    d->swizzle_g = s[1];
    d->swizzle_b = s[2];
    d->swizzle_a = s[3];
}
NVN_API(nvnTextureBuilderSetSamples) { TB(c)->d.samples = (int)arg_x(c, 1); }
NVN_API(nvnTextureBuilderSetStride) { TB(c)->d.stride = (uint32_t)arg_x(c, 1); }
// void nvnTextureBuilderSetStorage(NVNtextureBuilder *b, NVNmemoryPool *p, ptrdiff_t offset)
NVN_API(nvnTextureBuilderSetStorage) {
    tex_builder_t *b = TB(c);
    b->pool = arg_p(c, 1);
    b->off = (int64_t)arg_x(c, 2);
}
// void nvnTextureBuilderSetPackagedTextureLayout(NVNtextureBuilder *b, const NVNpackagedTextureLayout *l)
NVN_API(nvnTextureBuilderSetPackagedTextureLayout) {
    tex_builder_t *b = TB(c);
    const NVNpackagedTextureLayout *l = arg_p(c, 1);
    b->has_layout = l != NULL;
    if (l) memcpy(b->layout, l->layout, 8);
    b->d.pkg_block_h = l ? l->layout[0] + 1 : 0;
}
// void nvnTextureBuilderSetPackagedTextureData(NVNtextureBuilder *b, const void *data): packaged (already GPU-laid-out)
// data, copied into the texture's pool storage at Initialize
NVN_API(nvnTextureBuilderSetPackagedTextureData) { TB(c)->pkg_data = arg_p(c, 1); }
NVN_API(nvnTextureBuilderGetPackagedTextureData) { ret_x(c, (uintptr_t)TB(c)->pkg_data); }
// Storage classes are opaque compatibility identifiers: all texture storage lives in byte-addressed pools and is decoded
// per texture description, so class 1 names that convention; buffer textures use class 0. Not a Tegra memory kind.
static uint64_t storage_class(const nvn_texdesc *d) { return d->target == NVN_TEXTURE_TARGET_BUFFER ? 0 : 1; }
NVN_API(nvnTextureBuilderGetStorageClass) { ret_x(c, storage_class(&TB(c)->d)); }
NVN_API(nvnTextureBuilderGetFlags) { ret_x(c, (uint32_t)TB(c)->d.flags); }
// size_t nvnTextureBuilderGetStorageSize(const NVNtextureBuilder *b)
NVN_API(nvnTextureBuilderGetStorageSize) {
    nvn_texlayout L;
    nvn_tex_layout(&TB(c)->d, &L);
    if (!L.bpb) rt_log("nvn: TextureBuilderGetStorageSize: unknown format %#x", TB(c)->d.format);
    ret_x(c, L.size);
}
// size_t nvnTextureBuilderGetStorageAlignment(const NVNtextureBuilder *b)
NVN_API(nvnTextureBuilderGetStorageAlignment) {
    nvn_texlayout L;
    nvn_tex_layout(&TB(c)->d, &L);
    ret_x(c, L.align);
}

// ---------- Sparse tile layout
// NVNtextureSparseTileLayout {int numTiledLevels, tileWidth, tileHeight, tileDepth; uint32_t reserved[4]}: how a
// sparse texture (one in a VIRTUAL pool, mapped tile by tile) is cut into 64 KiB tiles. Maxwell's tiles, in blocks,
// by bytes per block: 1 -> 256x256, 2 -> 256x128, 4 -> 128x128, 8 -> 128x64, 16 -> 64x64; a 3D texture's tile has
// depth and a smaller face. The levels at least one tile wide and high are tiled; the smaller ones go into the mip
// tail, which is not sparse. This game (first seen in its opening cinematic) is the first on this host to ask.
typedef struct { int32_t levels, w, h, d; uint32_t reserved[4]; } sparse_layout_t;

static void sparse_layout(const nvn_texdesc *d, sparse_layout_t *o) {
    int bw = 1, bh = 1, bpb = nvn_fmt_bpb(d->format, &bw, &bh);
    memset(o, 0, sizeof *o);
    if (!bpb) {
        rt_log("nvn: sparse tile layout: unknown format %#x", d->format);
        return;
    }
    int tw, th, td = 1;
    switch (bpb) {
    case 1: tw = 256, th = 256; break;
    case 2: tw = 256, th = 128; break;
    case 4: tw = 128, th = 128; break;
    case 8: tw = 128, th = 64; break;
    default: tw = 64, th = 64; break;   // 16
    }
    int is_3d = d->target == NVN_TEXTURE_TARGET_3D;
    if (is_3d) {   // the same 64 KiB as 16 slices of a quarter-size face
        tw /= 4, th /= 4, td = 16;
        if (bpb >= 8) tw *= 2, th /= 2;
    }
    tw *= bw, th *= bh;
    int tiled = 0;
    for (uint32_t l = 0; l < d->levels; l++) {
        uint32_t w = d->width >> l, h = d->height >> l;
        if (w < (uint32_t)tw || h < (uint32_t)th) break;
        tiled++;
    }
    o->levels = tiled, o->w = tw, o->h = th, o->d = td;
    static volatile LONG said;
    if (InterlockedIncrement(&said) <= 4)
        rt_log("nvn: sparse tile layout of %ux%ux%u format %#x target %d, %u levels: %dx%dx%d tiles, %d tiled levels", d->width,
               d->height, d->depth, d->format, d->target, d->levels, tw, th, td, tiled);
}
// void nvnTextureBuilderGetSparseTileLayout(const NVNtextureBuilder *b, NVNtextureSparseTileLayout *out)
NVN_API(nvnTextureBuilderGetSparseTileLayout) { sparse_layout(&TB(c)->d, arg_p(c, 1)); }

// ---------- Textures
// The game re-initializes transient textures (G-buffer and the like) every frame at the same pool memory without
// registering the descriptor again, as an NVN descriptor refers to memory and stays valid on hardware. The table maps
// storage address -> a copy of the live texture so the back end can redirect a registration whose serial was finalized.
static nvn_hmap live = {.klen = 8};
static SRWLOCK live_lock = SRWLOCK_INIT;

static void live_put(const tex_t *o) {
    if (!o->mem) return;
    uint64_t k = (uintptr_t)o->mem;
    tex_t *copy = malloc(sizeof *copy);
    if (!copy) rt_fatal("nvn: out of memory for the live texture table");
    *copy = *o;
    AcquireSRWLockExclusive(&live_lock);
    tex_t *old = nvn_hm_put(&live, &k, copy);
    ReleaseSRWLockExclusive(&live_lock);
    free(old);
}

static void live_del(const tex_t *o) {
    if (!o->mem) return;
    uint64_t k = (uintptr_t)o->mem;
    AcquireSRWLockExclusive(&live_lock);
    tex_t *cur = nvn_hm_get(&live, &k);
    if (cur && cur->serial == o->serial) nvn_hm_del(&live, &k);
    else cur = NULL;
    ReleaseSRWLockExclusive(&live_lock);
    free(cur);
}

int nvn_tex_live_at(const void *mem, tex_t *out) {
    if (!mem) return 0;
    uint64_t k = (uintptr_t)mem;
    AcquireSRWLockShared(&live_lock);
    const tex_t *cur = nvn_hm_get(&live, &k);
    if (cur) *out = *cur;
    ReleaseSRWLockShared(&live_lock);
    return cur != NULL;
}

// Releases the back end's texture and the live entry of an initialized texture object.
static void tex_release(tex_t *o) {
    live_del(o);
    gfx_backend()->texture_release(o);
}

// NVNboolean nvnTextureInitialize(NVNtexture *t, const NVNtextureBuilder *b)
NVN_API(nvnTextureInitialize) {
    tex_t *o = arg_p(c, 0);
    const tex_builder_t *s = arg_p(c, 1);
    if (o->magic == NVN_TEX_MAGIC && o->serial) {   // initialized again without Finalize: release the old serial
        NVN_LOG("texture %p initialized again without Finalize (serial %llu released)", (void *)o,
                (unsigned long long)o->serial);
        tex_release(o);
    }
    memset(o, 0, sizeof *o);
    o->magic = NVN_TEX_MAGIC;
    o->d = s->d;
    o->pool = s->pool;
    o->off = s->off;
    o->has_layout = s->has_layout;
    memcpy(o->layout, s->layout, 8);
    nvn_tex_layout(&o->d, &o->L);
    o->mem = s->pool && s->pool->mem ? s->pool->mem + s->off : NULL;
    if (s->pkg_data) {
        if (!o->mem || nvn_gpu_only((uintptr_t)o->mem))
            rt_fatal("nvn: packaged texture data without CPU-visible storage");
        memcpy(o->mem, s->pkg_data, (size_t)o->L.size);
        nvn_guest_written((uintptr_t)o->mem, o->L.size);
    }
    o->serial = nvn_new_serial();
    live_put(o);
    NVN_LOG("Texture %p %ux%ux%u lv%u fmt=%#x tgt=%d flags=%#x size=%#llx", (void *)o, o->d.width, o->d.height,
            o->d.depth, o->d.levels, o->d.format, o->d.target, o->d.flags, (unsigned long long)o->L.size);
    ret_x(c, 1);
}
// void nvnTextureFinalize(NVNtexture *t)
NVN_API(nvnTextureFinalize) {
    tex_t *o = arg_p(c, 0);
    if (o->magic == NVN_TEX_MAGIC && o->serial) tex_release(o);
    o->magic = 0;
}
#define CTX(c) ((const tex_t *)arg_p(c, 0))
NVN_API(nvnTextureGetStorageClass) { ret_x(c, storage_class(&CTX(c)->d)); }
NVN_API(nvnTextureGetFlags) { ret_x(c, (uint32_t)CTX(c)->d.flags); }
NVN_API(nvnTextureGetWidth) { ret_x(c, CTX(c)->d.width); }
NVN_API(nvnTextureGetHeight) { ret_x(c, CTX(c)->d.height); }
NVN_API(nvnTextureGetDepth) { ret_x(c, CTX(c)->d.depth); }
NVN_API(nvnTextureGetStorageSize) { ret_x(c, (uint32_t)(int)CTX(c)->L.size); }
// void nvnTextureGetSparseTileLayout(const NVNtexture *t, NVNtextureSparseTileLayout *out)
NVN_API(nvnTextureGetSparseTileLayout) { sparse_layout(&CTX(c)->d, arg_p(c, 1)); }
// NVNboolean nvnTextureCompare(const NVNtexture *a, const NVNtexture *b)
NVN_API(nvnTextureCompare) {
    const tex_t *x = arg_p(c, 0), *y = arg_p(c, 1);
    ret_x(c, !memcmp(&x->d, &y->d, sizeof x->d) && x->mem == y->mem);
}
// int nvnTextureGetRawStorageClass(const NVNtexture *t): no prototype in nvn.h. Call sites compare the result with 1
// and set a status bit when it differs; the meaning is unverified, so 1.
NVN_API(nvnTextureGetRawStorageClass) { ret_x(c, 1); }

// ---------- Texture views
#define VW(c) ((view_t *)arg_p(c, 0))
NVN_API(nvnTextureViewSetDefaults) { memset(arg_p(c, 0), 0, sizeof(view_t)); }
NVN_API(nvnTextureViewSetLevels) {
    uint32_t base = (uint32_t)arg_x(c, 1), n = (uint32_t)arg_x(c, 2);
    if (base > 255 || n > 255) rt_fatal("nvn: texture view levels %d/%d", (int)base, (int)n);
    view_t *v = VW(c);
    v->set_levels = 1;
    v->base_level = (uint8_t)base;
    v->nlevels = (uint8_t)n;
}
NVN_API(nvnTextureViewSetLayers) {
    uint32_t first = (uint32_t)arg_x(c, 1), n = (uint32_t)arg_x(c, 2);
    if (first > 65535 || n > 65535) rt_fatal("nvn: texture view layers %d/%d", (int)first, (int)n);
    view_t *v = VW(c);
    v->set_layers = 1;
    v->min_layer = (uint16_t)first;
    v->nlayers = (uint16_t)n;
}
NVN_API(nvnTextureViewSetFormat) {
    uint32_t f = (uint32_t)arg_x(c, 1);
    if (f > 65535) rt_fatal("nvn: texture view format %d", (int)f);
    view_t *v = VW(c);
    v->set_format = 1;
    v->format = (uint16_t)f;
}
NVN_API(nvnTextureViewSetTarget) {
    uint32_t t = (uint32_t)arg_x(c, 1);
    if (t > 255) rt_fatal("nvn: texture view target %d", (int)t);
    view_t *v = VW(c);
    v->set_target = 1;
    v->target = (uint8_t)t;
}
// NVNboolean nvnTextureViewGetLayers(const NVNtextureView *v, int *min, int *n)
NVN_API(nvnTextureViewGetLayers) {
    const view_t *v = arg_p(c, 0);
    *(int *)arg_p(c, 1) = v->min_layer;
    *(int *)arg_p(c, 2) = v->nlayers;
    ret_x(c, v->set_layers);
}

uint64_t nvn_tex_view_offset(const tex_t *t, const view_t *v) {
    if (!v) return 0;
    uint64_t off = v->set_levels ? nvn_tex_level_offset(&t->d, v->base_level) : 0;
    if (v->set_layers) off += (uint64_t)v->min_layer * t->L.layer_size;
    return off;
}
// ptrdiff_t nvnTextureGetViewOffset(const NVNtexture *t, const NVNtextureView *v)
NVN_API(nvnTextureGetViewOffset) { ret_x(c, nvn_tex_view_offset(arg_p(c, 0), arg_p(c, 1))); }

// ---------- Texel access: the back end decodes the view's level and layer
// row / img: 0 means tightly packed
static void texel_strides(const tex_t *o, const NVNcopyRegion *r, uint64_t *row, uint64_t *img, const char *what) {
    int bw, bh, bpb = nvn_fmt_bpb(o->d.format, &bw, &bh);
    if (!bpb) rt_fatal("nvn: %s: unknown format %#x", what, o->d.format);
    uint64_t wb = (uint64_t)(((uint32_t)r->width + bw - 1) / bw) * bpb, hb = ((uint32_t)r->height + bh - 1) / bh;
    if (!*row) *row = wb;
    if (!*img) *img = *row * hb;
    if (*row < wb || *img < *row * hb) rt_fatal("nvn: %s: stride smaller than the region", what);
}
// void nvnTextureReadTexels[Strided](const NVNtexture *t, const NVNtextureView *v, const NVNcopyRegion *r, void *dst
// [, ptrdiff_t row, ptrdiff_t img])
static void read_texels(Cpu *c, int strided) {
    const tex_t *o = arg_p(c, 0);
    const NVNcopyRegion *r = arg_p(c, 2);
    uint64_t row = strided ? arg_x(c, 4) : 0, img = strided ? arg_x(c, 5) : 0;
    texel_strides(o, r, &row, &img, "ReadTexels");
    NVN_BLOCKING();
    gfx_backend()->read_texels(o, arg_p(c, 1), r, arg_p(c, 3), row, img);
}
// void nvnTextureWriteTexels[Strided](const NVNtexture *t, const NVNtextureView *v, const NVNcopyRegion *r, const void
// *src[, ptrdiff_t row, ptrdiff_t img])
static void write_texels(Cpu *c, int strided) {
    const tex_t *o = arg_p(c, 0);
    const view_t *v = arg_p(c, 1);
    const NVNcopyRegion *r = arg_p(c, 2);
    uint64_t row = strided ? arg_x(c, 4) : 0, img = strided ? arg_x(c, 5) : 0;
    texel_strides(o, r, &row, &img, "WriteTexels");
    if (v && v->set_format && v->format != o->d.format) rt_fatal("nvn: WriteTexels: format-reinterpreting view not supported");
    NVN_BLOCKING();
    gfx_backend()->write_texels(o, v, r, arg_p(c, 3), row, img);
}
NVN_API(nvnTextureReadTexels) { read_texels(c, 0); }
NVN_API(nvnTextureReadTexelsStrided) { read_texels(c, 1); }
NVN_API(nvnTextureWriteTexels) { write_texels(c, 0); }
NVN_API(nvnTextureWriteTexelsStrided) { write_texels(c, 1); }
// void nvnTexture{Flush,Invalidate}Texels(const NVNtexture *t, const NVNtextureView *v, const NVNcopyRegion *r): texel
// access is coherent
NVN_API(nvnTextureFlushTexels) { (void)c; }
NVN_API(nvnTextureInvalidateTexels) { (void)c; }

// ---------- Samplers
#define SB(c) (&((samp_builder_t *)arg_p(c, 0))->p)
// void nvnSamplerBuilderSetDefaults(NVNsamplerBuilder *b): keeps the device; GL defaults
NVN_API(nvnSamplerBuilderSetDefaults) {
    samp_builder_t *b = arg_p(c, 0);
    NVNdevice *dev = b->dev;
    memset(b, 0, sizeof *b);
    b->dev = dev;
    samp_par *o = &b->p;
    o->minf = NVN_MIN_FILTER_NEAREST_MIPMAP_LINEAR;
    o->magf = NVN_MAG_FILTER_LINEAR;
    o->ws = o->wt = o->wr = NVN_WRAP_MODE_REPEAT;
    o->cmp_func = NVN_COMPARE_FUNC_LESS;
    o->lod_min = -1000.f;
    o->lod_max = 1000.f;
    o->aniso = 1.f;
}
NVN_API(nvnSamplerBuilderSetDevice) { ((samp_builder_t *)arg_p(c, 0))->dev = arg_p(c, 1); }
NVN_API(nvnSamplerBuilderSetMinMagFilter) {
    samp_par *p = SB(c);
    p->minf = (uint8_t)arg_x(c, 1);
    p->magf = (uint8_t)arg_x(c, 2);
}
NVN_API(nvnSamplerBuilderSetWrapMode) {
    samp_par *p = SB(c);
    p->ws = (uint8_t)arg_x(c, 1);
    p->wt = (uint8_t)arg_x(c, 2);
    p->wr = (uint8_t)arg_x(c, 3);
}
// void nvnSamplerBuilderSetLodClamp(NVNsamplerBuilder *b, float min, float max): the floats arrive in v0, v1
NVN_API(nvnSamplerBuilderSetLodClamp) {
    samp_par *p = SB(c);
    p->lod_min = arg_s(c, 0);
    p->lod_max = arg_s(c, 1);
}
NVN_API(nvnSamplerBuilderSetLodBias) { SB(c)->lod_bias = arg_s(c, 0); }
NVN_API(nvnSamplerBuilderSetCompare) {
    samp_par *p = SB(c);
    p->cmp_mode = (uint8_t)arg_x(c, 1);
    p->cmp_func = (uint8_t)arg_x(c, 2);
}
NVN_API(nvnSamplerBuilderSetBorderColor) { memcpy(SB(c)->border, arg_p(c, 1), 16); }
NVN_API(nvnSamplerBuilderSetMaxAnisotropy) { SB(c)->aniso = arg_s(c, 0); }
NVN_API(nvnSamplerBuilderSetLodSnap) { SB(c)->lod_snap = arg_s(c, 0); }   // stored for queries; no host equivalent
// void nvnSamplerBuilderGetMinMagFilter(const NVNsamplerBuilder *b, NVNminFilter *min, NVNmagFilter *mag)
NVN_API(nvnSamplerBuilderGetMinMagFilter) {
    const samp_par *p = SB(c);
    *(uint32_t *)arg_p(c, 1) = p->minf;
    *(uint32_t *)arg_p(c, 2) = p->magf;
}
// void nvnSamplerBuilderGetWrapMode(const NVNsamplerBuilder *b, NVNwrapMode *s, NVNwrapMode *t, NVNwrapMode *r)
NVN_API(nvnSamplerBuilderGetWrapMode) {
    const samp_par *p = SB(c);
    *(uint32_t *)arg_p(c, 1) = p->ws;
    *(uint32_t *)arg_p(c, 2) = p->wt;
    *(uint32_t *)arg_p(c, 3) = p->wr;
}
NVN_API(nvnSamplerBuilderSetReductionFilter) {
    uint32_t r = (uint32_t)arg_x(c, 1);
    if (r > 2) rt_fatal("nvn: invalid sampler reduction %u", r);
    SB(c)->reduction = (uint8_t)r;
}
NVN_API(nvnSamplerBuilderGetReductionFilter) { ret_x(c, SB(c)->reduction); }
NVN_API(nvnSamplerGetReductionFilter) { ret_x(c, ((const samp_t *)arg_p(c, 0))->p.reduction); }
// NVNboolean nvnSamplerInitialize(NVNsampler *s, const NVNsamplerBuilder *b)
NVN_API(nvnSamplerInitialize) {
    samp_t *o = arg_p(c, 0);
    o->magic = NVN_SAMP_MAGIC;
    o->p = ((const samp_builder_t *)arg_p(c, 1))->p;
    ret_x(c, 1);
}
NVN_API(nvnSamplerFinalize) { ((samp_t *)arg_p(c, 0))->magic = 0; }

// ---------- Programs
// NVNboolean nvnProgramInitialize(NVNprogram *p, NVNdevice *d)
NVN_API(nvnProgramInitialize) {
    prog_t *o = arg_p(c, 0);
    memset(o, 0, sizeof *o);
    o->magic = NVN_PROG_MAGIC;
    ret_x(c, 1);
}
// NVNboolean nvnProgramInitializeFromBuilder(NVNprogram *p, const NVNprogramBuilder *b) (NVN2): nvnProgramInitialize
// plus nvnProgramSetShaders with the stages the builder was given (nvn_api.h nvn2_prog_builder_t)
static int prog_set_shaders(prog_t *o, int n, const NVNshaderData *sd);
NVN_API(nvnProgramInitializeFromBuilder) {
    NVN_BLOCKING();
    prog_t *o = arg_p(c, 0);
    const nvn2_prog_builder_t *b = arg_p(c, 1);
    memset(o, 0, sizeof *o);
    o->magic = NVN_PROG_MAGIC;
    ret_x(c, prog_set_shaders(o, b->nshaders, (const NVNshaderData *)(uintptr_t)b->shaders));
}
static void prog_release(prog_t *o) {
    if (o->serial) gfx_backend()->program_release(o);
    o->serial = 0;
}
// void nvnProgramFinalize(NVNprogram *p)
NVN_API(nvnProgramFinalize) {
    prog_t *o = arg_p(c, 0);
    prog_release(o);
    o->magic = 0;
}
static int prog_set_shaders(prog_t *o, int n, const NVNshaderData *sd) {
    if (n < 0 || n > 6 || (n && !sd)) {
        rt_log("nvn: ProgramSetShaders with %d stages at %p", n, (const void *)sd);
        return 0;
    }
    prog_release(o);
    o->nstage = (uint32_t)n;
    if (n) memcpy(o->sd, sd, (size_t)n * sizeof *sd);
    {   // Each distinct combination of the stages' control byte +0x56 (NVN2 stage numbers) is logged once, to see
        // which stage kinds the game's programs carry (the level draws with mesh tasks, 2026-11-06).
        static uint32_t seen[64];
        static int nseen;
        static SRWLOCK lk = SRWLOCK_INIT;
        uint32_t key = (uint32_t)n;
        for (int i = 0; i < n && i < 6; i++) key |= (uint32_t)(sd[i].control ? ((const uint8_t *)sd[i].control)[0x56] & 0xf : 0xf) << (4 + 4 * i);
        AcquireSRWLockExclusive(&lk);
        int found = 0;
        for (int i = 0; i < nseen; i++) found |= seen[i] == key;
        if (!found && nseen < 64) {
            seen[nseen++] = key;
            char buf[64] = {0};
            for (int i = 0; i < n && i < 6; i++) snprintf(buf + strlen(buf), sizeof buf - strlen(buf), " %u", key >> (4 + 4 * i) & 0xf);
            rt_log("nvn: a program with %d stages, NVN2 stage numbers%s", n, buf);
        }
        ReleaseSRWLockExclusive(&lk);
        // OOT_MESH_DUMP=<dir> (diagnostic): the control block (0x400 bytes) and code of every stage of the first 12
        // programs with a task (6) or mesh (7) stage, as <k>_s<stage>.ctl / .code, for tools/sm86_dis.py.
        // OOT_MESH_DUMP_STAGE=<n>: only programs with stage n (6: task programs). A program whose stages' code is
        // the same as one dumped before (the first 16 bytes after the header and the length) is not dumped again.
        static volatile LONG dumped;
        static uint64_t done_sig[64];
        static int ndone;
        const char *dir = cfg_get("OOT_MESH_DUMP"), *want = cfg_get("OOT_MESH_DUMP_STAGE");
        int mesh = 0, wanted = !(want && *want);
        uint64_t sig = 0xcbf29ce484222325ull;
        for (int i = 0; i < n; i++) {
            const uint8_t *ctl = sd[i].control;
            if (!ctl) continue;
            mesh |= (ctl[0x56] & 0xe) == 6;
            if (want && *want && ctl[0x56] == (uint8_t)atoi(want)) wanted = 1;
            uint32_t len;
            memcpy(&len, ctl + 0x44, 4);
            sig = (sig ^ len) * 0x100000001b3ull;
            if (sd[i].data && len >= 0x90) {
                uint64_t w;
                memcpy(&w, (const uint8_t *)(uintptr_t)sd[i].data + 0x80, 8);
                sig = (sig ^ w) * 0x100000001b3ull;
            }
        }
        if (mesh && wanted && dir && *dir) {
            AcquireSRWLockExclusive(&lk);
            for (int i = 0; i < ndone; i++) wanted &= done_sig[i] != sig;
            if (wanted && ndone < 64) done_sig[ndone++] = sig;
            ReleaseSRWLockExclusive(&lk);
        }
        LONG k = mesh && wanted && dir && *dir ? InterlockedIncrement(&dumped) : 0;
        for (int i = 0; k && k <= 12 && i < n; i++) {
            const uint8_t *ctl = sd[i].control;
            if (!ctl || !sd[i].data) continue;
            uint32_t len;
            memcpy(&len, ctl + 0x44, 4);
            char path[600];
            snprintf(path, sizeof path, "%s\\%02ld_s%u.ctl", dir, (long)k, ctl[0x56]);
            plat_file_write(path, ctl, 0x400);
            snprintf(path, sizeof path, "%s\\%02ld_s%u.code", dir, (long)k, ctl[0x56]);
            if (len < (16u << 20)) plat_file_write(path, (const void *)(uintptr_t)sd[i].data, len);
        }
    }
    if (getenv("OOT_PROG_DUMP")) {   // DIAG: the memory around a compute program's control section (NVN2 bank 0 layout)
        static volatile LONG shown;
        for (int i = 0; i < n; i++) {
            const uint8_t *ctl = sd[i].control;
            if (!ctl || ctl[0x56] != 5 || InterlockedIncrement(&shown) > 6) continue;
            rt_log("progdump: stage 5 data %#llx control %p", (unsigned long long)sd[i].data, (const void *)ctl);
            for (int off = -0x80; off < 0x300; off += 32) {
                char line[3 * 32 + 1];
                for (int k = 0; k < 32; k++) snprintf(line + 3 * k, 4, "%02x ", ctl[off + k]);
                rt_log("progdump: %+#06x: %s", off, line);
            }
        }
    }
    o->serial = nvn_new_serial();
    NVN_LOG("ProgramSetShaders %p n=%d data0=%#llx", (void *)o, n, n ? (unsigned long long)sd[0].data : 0ull);
    return 1;
}
// NVNboolean nvnProgramSetShaders(NVNprogram *p, int n, const NVNshaderData *sd)
NVN_API(nvnProgramSetShaders) {
    NVN_BLOCKING();
    ret_x(c, prog_set_shaders(arg_p(c, 0), (int)arg_x(c, 1), arg_p(c, 2)));
}
// NVNboolean nvnProgramSetShadersExt(NVNprogram *p, int n, const NVNshaderDataExt *sd): no prototype in nvn.h; the
// entries are {data, control, reserved} (0x18 bytes, reserved observed 0)
typedef struct { NVNbufferAddress data; const void *control; uint64_t reserved; } shader_data_ext;
_Static_assert(sizeof(shader_data_ext) == 0x18, "NVNshaderDataExt stride");
NVN_API(nvnProgramSetShadersExt) {
    NVN_BLOCKING();
    prog_t *o = arg_p(c, 0);
    int n = (int)arg_x(c, 1);
    const shader_data_ext *sd = arg_p(c, 2);
    if (n < 0 || n > 6 || (n && !sd)) {
        rt_log("nvn: ProgramSetShadersExt with %d stages at %p", n, (const void *)sd);
        ret_x(c, 0);
        return;
    }
    NVNshaderData plain[6];
    for (int i = 0; i < n; i++) {
        if (sd[i].reserved)
            rt_fatal("nvn: ProgramSetShadersExt: unknown non-zero field %#llx in stage %d", (unsigned long long)sd[i].reserved, i);
        plain[i] = (NVNshaderData){sd[i].data, sd[i].control};
    }
    ret_x(c, prog_set_shaders(o, n, plain));
}

// ---------- State objects: packed in place (nvn_obj.h)
#define ST(T, c) ((T *)arg_p(c, 0))
NVN_API(nvnBlendStateSetDefaults) {
    *ST(blend_st, c) = (blend_st){0, NVN_BLEND_FUNC_ONE, NVN_BLEND_FUNC_ZERO, NVN_BLEND_FUNC_ONE, NVN_BLEND_FUNC_ZERO,
                                  NVN_BLEND_EQUATION_ADD, NVN_BLEND_EQUATION_ADD};
}
NVN_API(nvnBlendStateSetBlendTarget) { ST(blend_st, c)->target = (uint32_t)arg_x(c, 1); }
NVN_API(nvnBlendStateSetBlendFunc) {
    blend_st *o = ST(blend_st, c);
    o->src_rgb = (uint32_t)arg_x(c, 1);
    o->dst_rgb = (uint32_t)arg_x(c, 2);
    o->src_a = (uint32_t)arg_x(c, 3);
    o->dst_a = (uint32_t)arg_x(c, 4);
}
NVN_API(nvnBlendStateSetBlendEquation) {
    blend_st *o = ST(blend_st, c);
    o->eq_rgb = (uint32_t)arg_x(c, 1);
    o->eq_a = (uint32_t)arg_x(c, 2);
}
NVN_API(nvnColorStateSetDefaults) { *ST(color_st, c) = (color_st){0, NVN_LOGIC_OP_COPY, NVN_ALPHA_FUNC_ALWAYS}; }
// void nvnColorStateSetBlendEnable(NVNcolorState *s, int index, NVNboolean enable)
NVN_API(nvnColorStateSetBlendEnable) {
    color_st *o = ST(color_st, c);
    int i = (int)arg_x(c, 1);
    if (i < 0 || i > 7) return;
    o->blend_en = nvn_arg_bool(c, 2) ? (o->blend_en | 1u << i) : (o->blend_en & ~(1u << i));
}
NVN_API(nvnChannelMaskStateSetDefaults) { ST(chmask_st, c)->mask = 0xffffffffu; }
// void nvnChannelMaskStateSetChannelMask(NVNchannelMaskState *s, int index, NVNboolean r, g, b, a)
NVN_API(nvnChannelMaskStateSetChannelMask) {
    int i = (int)arg_x(c, 1);
    if (i < 0 || i > 7) return;
    uint32_t m = (nvn_arg_bool(c, 2) ? 1u : 0) | (nvn_arg_bool(c, 3) ? 2u : 0) | (nvn_arg_bool(c, 4) ? 4u : 0) |
                 (nvn_arg_bool(c, 5) ? 8u : 0);
    chmask_st *o = ST(chmask_st, c);
    o->mask = (o->mask & ~(0xfu << (4 * i))) | m << (4 * i);
}
NVN_API(nvnMultisampleStateSetDefaults) {
    memset(arg_p(c, 0), 0, sizeof(ms_st));
    ST(ms_st, c)->enable = 1;
}
NVN_API(nvnMultisampleStateSetMultisampleEnable) { ST(ms_st, c)->enable = nvn_arg_bool(c, 1) != 0; }
NVN_API(nvnMultisampleStateSetSamples) { ST(ms_st, c)->samples = (uint8_t)arg_x(c, 1); }
NVN_API(nvnMultisampleStateSetAlphaToCoverageEnable) { ST(ms_st, c)->a2c = nvn_arg_bool(c, 1) != 0; }
NVN_API(nvnMultisampleStateSetSampleLocationsEnable) { ST(ms_st, c)->sl_en = nvn_arg_bool(c, 1) != 0; }
// void nvnMultisampleStateSetSampleLocations(NVNmultisampleState *s, int start, int n, const float *v): programmable
// sample positions are not replayed
NVN_API(nvnMultisampleStateSetSampleLocations) { (void)c; }
NVN_API(nvnPolygonStateSetDefaults) {
    *ST(poly_st, c) = (poly_st){NVN_FACE_NONE, NVN_FRONT_FACE_CCW, NVN_POLYGON_MODE_FILL, 0};
}
NVN_API(nvnPolygonStateSetCullFace) { ST(poly_st, c)->cull = (uint32_t)arg_x(c, 1); }
NVN_API(nvnPolygonStateSetFrontFace) { ST(poly_st, c)->front = (uint32_t)arg_x(c, 1); }
NVN_API(nvnPolygonStateSetPolygonMode) { ST(poly_st, c)->mode = (uint32_t)arg_x(c, 1); }
NVN_API(nvnPolygonStateSetPolygonOffsetEnables) { ST(poly_st, c)->offset_en = (uint32_t)arg_x(c, 1); }
NVN_API(nvnDepthStencilStateSetDefaults) {
    *ST(ds_st, c) = (ds_st){0, 1, NVN_DEPTH_FUNC_LESS, 0, NVN_STENCIL_FUNC_ALWAYS, NVN_STENCIL_FUNC_ALWAYS,
                            NVN_STENCIL_OP_KEEP, NVN_STENCIL_OP_KEEP, NVN_STENCIL_OP_KEEP,
                            NVN_STENCIL_OP_KEEP, NVN_STENCIL_OP_KEEP, NVN_STENCIL_OP_KEEP};
}
NVN_API(nvnDepthStencilStateSetDepthTestEnable) { ST(ds_st, c)->dt = nvn_arg_bool(c, 1) != 0; }
NVN_API(nvnDepthStencilStateSetDepthWriteEnable) { ST(ds_st, c)->dw = nvn_arg_bool(c, 1) != 0; }
NVN_API(nvnDepthStencilStateSetDepthFunc) { ST(ds_st, c)->df = (uint32_t)arg_x(c, 1); }
NVN_API(nvnDepthStencilStateSetStencilTestEnable) { ST(ds_st, c)->st = nvn_arg_bool(c, 1) != 0; }
// void nvnDepthStencilStateSetStencilFunc(NVNdepthStencilState *s, NVNface face, NVNstencilFunc func)
NVN_API(nvnDepthStencilStateSetStencilFunc) {
    ds_st *o = ST(ds_st, c);
    uint32_t face = (uint32_t)arg_x(c, 1), fn = (uint32_t)arg_x(c, 2);
    if (face & NVN_FACE_FRONT) o->sf_f = fn;
    if (face & NVN_FACE_BACK) o->sf_b = fn;
}
// void nvnDepthStencilStateSetStencilOp(NVNdepthStencilState *s, NVNface face, NVNstencilOp fail, zfail, zpass)
NVN_API(nvnDepthStencilStateSetStencilOp) {
    ds_st *o = ST(ds_st, c);
    uint32_t face = (uint32_t)arg_x(c, 1), fail = (uint32_t)arg_x(c, 2), zfail = (uint32_t)arg_x(c, 3),
             zpass = (uint32_t)arg_x(c, 4);
    if (face & NVN_FACE_FRONT) { o->fail_f = fail; o->zfail_f = zfail; o->zpass_f = zpass; }
    if (face & NVN_FACE_BACK) { o->fail_b = fail; o->zfail_b = zfail; o->zpass_b = zpass; }
}
NVN_API(nvnVertexAttribStateSetDefaults) { *ST(va_st, c) = (va_st){0, 0, 0}; }
// void nvnVertexAttribStateSetFormat(NVNvertexAttribState *s, NVNformat format, ptrdiff_t offset)
NVN_API(nvnVertexAttribStateSetFormat) {
    int64_t off = (int64_t)arg_x(c, 2);
    if (off < 0 || off >= (1 << 19)) rt_fatal("nvn: vertex attribute offset %lld outside the packed range", (long long)off);
    va_st *o = ST(va_st, c);
    o->fmt = (uint32_t)arg_x(c, 1);
    o->offset = (uint32_t)off;
}
NVN_API(nvnVertexAttribStateSetStreamIndex) { ST(va_st, c)->stream = (uint32_t)arg_x(c, 1); }
NVN_API(nvnVertexStreamStateSetDefaults) { *ST(vs_st, c) = (vs_st){0, 0}; }
NVN_API(nvnVertexStreamStateSetStride) { ST(vs_st, c)->stride = (uint32_t)arg_x(c, 1); }
NVN_API(nvnVertexStreamStateSetDivisor) { ST(vs_st, c)->divisor = (uint32_t)arg_x(c, 1); }

// ---------- Windows
#define WB(c) ((win_builder_t *)arg_p(c, 0))
#define WN(c) ((win_t *)arg_p(c, 0))
NVN_API(nvnWindowBuilderSetDefaults) {
    win_builder_t *b = WB(c);
    NVNdevice *dev = b->dev;
    memset(b, 0, sizeof *b);
    b->dev = dev;
    b->interval = 1;
}
NVN_API(nvnWindowBuilderSetDevice) { WB(c)->dev = arg_p(c, 1); }
NVN_API(nvnWindowBuilderSetNativeWindow) { WB(c)->native = arg_p(c, 1); }
// void nvnWindowBuilderSetTextures(NVNwindowBuilder *b, int n, NVNtexture *const *textures)
NVN_API(nvnWindowBuilderSetTextures) {
    win_builder_t *b = WB(c);
    int n = (int)arg_x(c, 1);
    NVNtexture *const *t = arg_p(c, 2);
    if (n < 0 || n > 4 || (n && !t)) rt_fatal("nvn: WindowBuilderSetTextures with %d textures at %p", n, (const void *)t);
    b->ntex = n;
    for (int i = 0; i < n; i++) b->tex[i] = t[i];
}
// TOTK sets two active images; the limit bounds what WindowAcquireTexture hands out. No prototype in nvn.h.
NVN_API(nvnWindowBuilderSetNumActiveTextures) {
    int n = (int)arg_x(c, 1);
    if (n < 2 || n > 4) rt_fatal("nvn: unsupported active texture count %d", n);
    WB(c)->active = n;
}
NVN_API(nvnWindowBuilderGetNumActiveTextures) {
    const win_builder_t *b = WB(c);
    ret_x(c, (uint32_t)(b->active ? b->active : b->ntex));
}
NVN_API(nvnWindowSetNumActiveTextures) {
    win_t *w = WN(c);
    int n = (int)arg_x(c, 1);
    if (n < 2 || n > w->ntex) rt_fatal("nvn: invalid active window texture count %d", n);
    w->active = n;
}
NVN_API(nvnWindowGetNumActiveTextures) {
    const win_t *w = WN(c);
    ret_x(c, (uint32_t)(w->active ? w->active : w->ntex));
}
NVN_API(nvnWindowBuilderSetPresentInterval) { WB(c)->interval = (int)arg_x(c, 1); }
// The windows alive, for nvn_window_uses_pool (vk_backend.c: a pool holding a window texture is freed only after the
// queued presents reading it were submitted). One window in practice; four is the NVN-side limit this keeps.
static win_t *g_windows[4];
static SRWLOCK g_windows_lock = SRWLOCK_INIT;

static void window_track(win_t *o, int alive) {
    AcquireSRWLockExclusive(&g_windows_lock);
    for (int i = 0; i < 4; i++)
        if (alive ? !g_windows[i] : g_windows[i] == o) {
            g_windows[i] = alive ? o : NULL;
            break;
        }
    ReleaseSRWLockExclusive(&g_windows_lock);
}

int nvn_window_uses_pool(const pool_t *p) {
    if (!p || !p->mem) return 0;
    uintptr_t lo = (uintptr_t)p->mem, hi = lo + p->size;
    int r = 0;
    AcquireSRWLockShared(&g_windows_lock);
    for (int i = 0; i < 4 && !r; i++)
        for (int k = 0; g_windows[i] && k < g_windows[i]->ntex && k < 4 && !r; k++) {
            const tex_t *t = (const tex_t *)g_windows[i]->tex[k];
            r = t && (uintptr_t)t->mem >= lo && (uintptr_t)t->mem < hi;
        }
    ReleaseSRWLockShared(&g_windows_lock);
    return r;
}

// NVNboolean nvnWindowInitialize(NVNwindow *w, const NVNwindowBuilder *b)
NVN_API(nvnWindowInitialize) {
    win_t *o = arg_p(c, 0);
    const win_builder_t *s = arg_p(c, 1);
    memset(o, 0, sizeof *o);
    o->magic = NVN_WIN_MAGIC;
    o->native = s->native;
    o->ntex = s->ntex;
    o->interval = s->interval;
    o->active = s->active ? s->active : s->ntex;
    if (o->ntex < 2 || o->ntex > 4 || o->active < 2 || o->active > o->ntex) {
        rt_log("nvn: WindowInitialize with %d textures, %d active", o->ntex, o->active);
        ret_x(c, 0);
        return;
    }
    rt_log("nvn: window of %d textures, %d active, interval %d", o->ntex, o->active, o->interval);
    memcpy(o->tex, s->tex, sizeof o->tex);
    const tex_t *t0 = (const tex_t *)o->tex[0];
    NVN_LOG("WindowInitialize %d textures, interval %d, first %ux%u format %#x", o->ntex, o->interval,
            t0 ? t0->d.width : 0, t0 ? t0->d.height : 0, t0 ? t0->d.format : 0);
    window_track(o, 1);
    ret_x(c, 1);
}
// void nvnWindowFinalize(NVNwindow *w): nothing to release (MNG lists it in g_nops) beyond the window list entry
NVN_API(nvnWindowFinalize) { window_track(arg_p(c, 0), 0); }
NVN_API(nvnWindowSetPresentInterval) {
    win_t *o = WN(c);
    int v = (int)arg_x(c, 1);
    if (o->interval != v) NVN_LOG("present interval %d -> %d", o->interval, v);
    o->interval = v;
}
// void nvnWindowSetCrop(NVNwindow *w, int x, int y, int w, int h)
NVN_API(nvnWindowSetCrop) {
    win_t *o = WN(c);
    int v[4] = {(int)arg_x(c, 1), (int)arg_x(c, 2), (int)arg_x(c, 3), (int)arg_x(c, 4)};
    if (memcmp(o->crop, v, sizeof v)) NVN_LOG("WindowCrop %d,%d %dx%d", v[0], v[1], v[2], v[3]);
    memcpy(o->crop, v, sizeof v);
}

// ---------- Present pacing
// The vsync thread ticks at a fixed 60 Hz whatever the monitor does, so one game frame lasts `interval` ticks. With
// the real-time frame step (frame_rate.c) game speed does not depend on the interval, so a frame is shown when it is
// ready, at most at the frame limit (OOT_FPS_LIMIT: 30 to 360 per second or the monitor's rate): holding it to the
// 2nd or 3rd tick would only add latency and 50 ms frames.
#define VSYNC_HZ 60ull
// ---- Adaptive interval
// The game asks for interval 1 (60 Hz) and, on the level, this port gives it about 38 fps: frames of one and of two
// vsync ticks alternate, and the game's frame timing alternates with them. On those frames Link's material shader
// writes NaN into his colour target, which the bloom and the upscaler spread over the whole picture, and the tone
// map makes it black: 4 of 17 shots on the recorded walk were black frames with only the HUD (build/logs/walk.txt,
// 2026-11-08; OOT_DUMP_TRACE showed the NaN first in Link's layer, every other frame). At a steady 60 or 30 fps there
// are none: OOT_GPU_AHEAD=0 (about 13 fps) and a fixed interval of 2 both remove them (0 of 53 shots). Hookshot finds
// the same frame-rate dependence (its "dark frames", none at 33 fps; read for behaviour only). So the pacer holds
// whole frame rates: 60 fps, or interval 2 (30 fps, as a console game that cannot hold 60 shows every frame for two
// vsyncs) while frames miss 60. It decides from the share of such frames in a sliding window of AP_WIN frames.
// Since 2026-11-10 the cause is known: not the uneven rate itself but the CPU a frame ahead of the GPU at it (the
// acquire below, ahead 0). Below 60 the pacer now keeps the game's interval and the CPU in step with the GPU
// (ap_var): a variable rate with no black frames, 35-47 fps in the Forest Temple where it held 30 (RTX 5070);
// OOT_PACE_LOW=30 brings the interval of 2 back. The rule:
// - At 60, a frame's cost is the time since the previous present less what its acquire slept for the pacer; the
//   acquire's GPU fence wait counts, so a GPU-bound frame misses too. AP_UP_N of the window's frames over AP_MISS_MS
//   (one tick and a margin for timer jitter): pace at 30.
// - At 30 that cost hides in the slack, so the pacer predicts what the frame would cost at 60: its CPU work (the time
//   since the previous present less every acquire wait) plus its GPU time (timestamps, vk_sync.c, averaged over the
//   last AP_GPU_N presents). The two barely overlap in this game: at 60 on the level the CPU waits for GPU fences
//   about 9.6 ms of each 20 ms frame (perf line, run-82). The prediction is high (the GPU also reads about 10% slower
//   at 30 than at 60 on the title), so AP_FIT_MS sits close to a tick. Back to 60 when a full window has at most
//   AP_DOWN_N frames predicted over AP_FIT_MS and the pacer has held 30 for ap_hold_ns.
// - The hold starts at AP_HOLD_S; when frames miss again within AP_RETRY_S of a return to 60 (a scene the prediction
//   gets wrong), the next hold doubles, up to AP_HOLD_MAX_S, so a wrong prediction costs a second of uneven frames
//   once per hold, not a flip every few seconds.
// The first rule (8 frames in a row over 18 ms of CPU work, back after 180 frames under 13 ms on average) saw neither
// GPU time nor a miss every other frame: on the RX 9070 XT it flipped between 30 and 60 on the level, whose frames
// at 60 take 14-38 ms (about 20 on average, CPU work 10-12 ms at 30), and left it at an uneven 46-49 fps with about
// half the frames black (19 of 41 shots, build/logs/run-82.log); it flipped the title too (CPU work 2 ms, GPU 18 ms).
// With this rule on the same GPU (docs/level.md, 2026-11-09): the level holds 30 fps, 0 black of 41 shots, every frame
// predicted over AP_FIT_MS (CPU work 10 + GPU 12.6 ms; run-88); the title runs at 60 with the shared-memory commit
// (CPU work 2.2 + GPU 9.4 ms; run-90) and holds 30 without it (predicted 20 ms; run-92).
// OOT_PRESENT_INTERVAL: unset or "auto" adaptive, 0 the game's interval always, n > 0 that many ticks always.
// OOT_TRACE=perf adds a line every AP_LOG_N presents with both measures and their percentiles, in every mode.
#define AP_WIN 120          // frames in the window: 2 s at 60 fps, 4 s at 30
#define AP_MISS_MS 17.5     // at 60: a frame that cost more missed its tick (16.7 ms and 5%)
#define AP_UP_N 12          // misses in the window that switch to 30 (10%)
#define AP_FIT_MS 16.0      // at 30: a frame predicted under this fits 60 (96% of a tick)
#define AP_DOWN_N 6         // frames of a full window predicted over AP_FIT_MS that still allow 60 (5%)
#define AP_GPU_N 8          // presents the GPU time is averaged over (it is counted at completion, not per frame)
#define AP_HOLD_S 5
#define AP_RETRY_S 10
#define AP_HOLD_MAX_S 320
#define AP_LOG_N 600
#define AP_S 1000000000ull
static int ap_mode = -2;                 // -1 adaptive, 0 the game's interval, n > 0 fixed
static int ap_ticks = 1;                 // adaptive: the interval paced at
static int ap_var = 1;                   // OOT_PACE_LOW: below 60 a variable rate in step with the GPU (1) or 30 (0)
static uint64_t ap_last_present, ap_switched, ap_hold_ns = AP_HOLD_S * AP_S;   // last change of interval, hold at 30
static volatile LONG64 ap_wait_ns, ap_sleep_ns;   // acquire waits since the last present, and the pacer's sleep in them
static uint64_t ap_gpu_tot[AP_GPU_N];    // perf_gpu_busy_total at the last AP_GPU_N presents
static unsigned ap_gpu_pos, ap_gpu_n;
// The window: per frame whether it argues for the other rate, and the measures for the log line at a change.
static struct { uint8_t bad; float cost, work, gpu; } ap_win[AP_WIN];
static int ap_pos, ap_n, ap_nbad;
static double ap_sum_cost, ap_sum_work, ap_sum_gpu;
// OOT_TRACE=perf: since the last line, with each frame's cost and prediction for the percentiles.
static struct { unsigned n, miss, over; double cost, work, gpu; float c[AP_LOG_N], p[AP_LOG_N]; } ap_log;

static int ap_cmp(const void *a, const void *b) {
    float x = *(const float *)a, y = *(const float *)b;
    return (x > y) - (x < y);
}

// The p-th percentile of n values, sorted in place.
static double ap_pct(float *v, unsigned n, double p) {
    qsort(v, n, sizeof *v, ap_cmp);
    unsigned i = (unsigned)(p * (n - 1) + 0.5);
    return v[i];
}

static void ap_init(void) {
    if (ap_mode != -2) return;
    const char *e = cfg_get("OOT_PRESENT_INTERVAL");
    ap_mode = !e || !*e || !strcmp(e, "auto") ? -1 : !strcmp(e, "alt") ? -3 : atoi(e) < 0 ? 0 : atoi(e);
    const char *low = cfg_get("OOT_PACE_LOW");
    ap_var = !(low && !strcmp(low, "30"));
    if (ap_mode == -1) {
        perf_gpu_timing_want();   // the prediction at 30 needs the GPU time
        rt_log("nvn: present interval adaptive: 60 fps, or %s while %d of %d frames miss 60 (OOT_PRESENT_INTERVAL, "
               "OOT_PACE_LOW)", ap_var ? "a variable rate with the CPU in step with the GPU" : "30", AP_UP_N, AP_WIN);
    } else if (ap_mode > 0) rt_log("nvn: OOT_PRESENT_INTERVAL=%d: presents paced to %d of 60 Hz", ap_mode, ap_mode);
    else if (ap_mode == -3) rt_log("nvn: OOT_PRESENT_INTERVAL=alt: presents alternate 1 and 2 ticks of 60 Hz (diagnostic: the uneven rate of the black frames)");
}

static void ap_window_reset(void) {
    memset(ap_win, 0, sizeof ap_win);
    ap_pos = ap_n = ap_nbad = 0;
    ap_sum_cost = ap_sum_work = ap_sum_gpu = 0;
}

static void ap_window_add(int bad, double cost, double work, double gpu) {
    if (ap_n == AP_WIN) {
        ap_nbad -= ap_win[ap_pos].bad;
        ap_sum_cost -= ap_win[ap_pos].cost, ap_sum_work -= ap_win[ap_pos].work, ap_sum_gpu -= ap_win[ap_pos].gpu;
    } else ap_n++;
    ap_win[ap_pos].bad = (uint8_t)bad;
    ap_win[ap_pos].cost = (float)cost, ap_win[ap_pos].work = (float)work, ap_win[ap_pos].gpu = (float)gpu;
    ap_nbad += bad;
    ap_sum_cost += cost, ap_sum_work += work, ap_sum_gpu += gpu;
    ap_pos = (ap_pos + 1) % AP_WIN;
}

// At each present, before its slot is taken: the frame that ends here goes into the window, which decides the interval.
static void ap_present(uint64_t now) {
    ap_init();
    uint64_t wait = (uint64_t)InterlockedExchange64(&ap_wait_ns, 0);
    uint64_t sleep = (uint64_t)InterlockedExchange64(&ap_sleep_ns, 0);
    uint64_t tot = perf_gpu_busy_total();
    uint64_t oldest = ap_gpu_tot[ap_gpu_n < AP_GPU_N ? 0 : ap_gpu_pos];   // ap_gpu_n presents ago
    double gpu = ap_gpu_n ? (double)(tot - oldest) / ap_gpu_n / 1e6 : 0.0;
    ap_gpu_tot[ap_gpu_pos] = tot;
    ap_gpu_pos = (ap_gpu_pos + 1) % AP_GPU_N;
    if (ap_gpu_n < AP_GPU_N) ap_gpu_n++;
    uint64_t gap = ap_last_present ? now - ap_last_present : 0;
    ap_last_present = now;
    if (!gap || gap > 250000000ull) return;   // the first present, loading or a stall: not a frame's work
    double cost = (gap > sleep ? (double)(gap - sleep) : 0.0) / 1e6;
    double work = (gap > wait ? (double)(gap - wait) : 0.0) / 1e6;
    int miss = cost > AP_MISS_MS, over = work + gpu > AP_FIT_MS;
    if (rt_trace & RT_TRACE_PERF) {
        ap_log.c[ap_log.n] = (float)cost, ap_log.p[ap_log.n] = (float)(work + gpu);
        ap_log.n++, ap_log.miss += miss, ap_log.over += over;
        ap_log.cost += cost, ap_log.work += work, ap_log.gpu += gpu;
        if (ap_log.n == AP_LOG_N) {
            double n = ap_log.n;
            rt_log("nvn: pacing at %d ticks: last %u frames: %.0f%% cost over %.1f ms (%.1f on average, median %.1f, "
                   "95th percentile %.1f), %.0f%% predicted over %.1f ms (CPU work %.1f + GPU %.1f on average; "
                   "median %.1f, 5th percentile %.1f, 95th %.1f)",
                   ap_mode == -1 ? ap_ticks : ap_mode, ap_log.n, 100.0 * ap_log.miss / n, AP_MISS_MS, ap_log.cost / n,
                   ap_pct(ap_log.c, ap_log.n, 0.5), ap_pct(ap_log.c, ap_log.n, 0.95), 100.0 * ap_log.over / n,
                   AP_FIT_MS, ap_log.work / n, ap_log.gpu / n, ap_pct(ap_log.p, ap_log.n, 0.5),
                   ap_pct(ap_log.p, ap_log.n, 0.05), ap_pct(ap_log.p, ap_log.n, 0.95));
            ap_log.n = ap_log.miss = ap_log.over = 0;
            ap_log.cost = ap_log.work = ap_log.gpu = 0;
        }
    }
    if (ap_mode != -1 || frame_step_realtime()) return;
    ap_window_add(ap_ticks == 1 ? miss : over, cost, work, gpu);
    double n = ap_n;
    if (ap_ticks == 1) {
        if (ap_nbad < AP_UP_N) return;
        // Frames miss again soon after a return to 60: the prediction was wrong here, so hold longer before the next.
        if (ap_switched && now - ap_switched < AP_RETRY_S * AP_S)
            ap_hold_ns = ap_hold_ns * 2 > AP_HOLD_MAX_S * AP_S ? AP_HOLD_MAX_S * AP_S : ap_hold_ns * 2;
        else ap_hold_ns = AP_HOLD_S * AP_S;
        rt_log("nvn: frames miss 60 Hz (%d of the last %d cost over %.1f ms, %.1f ms on average; GPU %.1f ms): "
               "%s for at least %llu s", ap_nbad, ap_n, AP_MISS_MS, ap_sum_cost / n, ap_sum_gpu / n,
               ap_var ? "variable rate, CPU in step with the GPU" : "pacing at 30 fps",
               (unsigned long long)(ap_hold_ns / AP_S));
        ap_ticks = 2;
    } else {
        if (ap_n < AP_WIN || ap_nbad > AP_DOWN_N || now - ap_switched < ap_hold_ns) return;
        rt_log("nvn: frames fit 60 Hz again (%d of the last %d predicted over %.1f ms; CPU work %.1f + GPU %.1f ms on "
               "average): pacing at 60 fps", ap_nbad, ap_n, AP_FIT_MS, ap_sum_work / n, ap_sum_gpu / n);
        ap_ticks = 1;
    }
    ap_switched = now;
    ap_window_reset();
}

static uint64_t present_period(const win_t *o) {
    if (frame_step_realtime()) return frame_step_cap_ns();
    ap_init();
    uint64_t ticks = o->interval > 0 ? (uint64_t)o->interval : 1ull;
    if (ap_mode > 0) ticks = (uint64_t)ap_mode;
    else if (ap_mode == -3) { static unsigned alt; ticks = 1 + (alt++ & 1); }
    else if (ap_mode == -1 && !ap_var && (uint64_t)ap_ticks > ticks) ticks = (uint64_t)ap_ticks;
    // ap_var below 60: the game's interval, so every frame goes out as soon as it is ready (pace: a late frame is
    // presented at once) and a variable-refresh display shows it then.
    return ticks * 1000000000ull / VSYNC_HZ;
}

// MacNativeGames nvn_pace.h: the present slot is the previous slot plus one period. Early: wait for the slot. Late by
// less than a period: present at once and keep the phase. Behind by a period or more: restart from now, no catch-up
// burst. Returns the ns to wait.
static uint64_t pace(uint64_t *target, uint64_t now, uint64_t period) {
    if (!period || !*target) { *target = now; return 0; }
    uint64_t next = *target + period;
    if (now <= next) { *target = next; return next - now; }
    *target = now - next < period ? next : now;
    return 0;
}

static void sleep_until(uint64_t deadline) {
    for (;;) {
        uint64_t now = kern_now_ns();
        if (now >= deadline) return;
        uint64_t d = deadline - now;
        if (d >= 2000000) Sleep((DWORD)(d / 1000000 - 1));
        else SwitchToThread();
    }
}

// NVNwindowAcquireTextureResult nvnWindowAcquireTexture(NVNwindow *w, NVNsync *s, int *index): blocks here, not in the
// present, until the image's previous present plus one period has passed (the game often presents with a lock held).
// That is the time the next frame goes to the display, so the image is free as soon as that time is reached.
NVN_API(nvnWindowAcquireTexture) {
    win_t *o = arg_p(c, 0);
    sync_t *s = arg_p(c, 1);
    int *out = arg_p(c, 2);
    NVN_BLOCKING();
    int idx = o->active ? o->next++ % o->active : 0;
    *out = idx;
    uint64_t at = idx < 4 ? o->avail[idx] : 0;
    uint64_t w0 = kern_now_ns();   // ap_present: what the acquire waits is not the frame's work
    if (at) {
        uint64_t p0 = perf_begin();
        sleep_until(at);
        perf_end(PERF_PACE, p0);
        InterlockedAdd64(&ap_sleep_ns, (LONG64)(kern_now_ns() - w0));   // the pacer's part of the wait
    }
    // The image is also free only once the GPU finished the frame it was last presented with: on the Switch the
    // display's release of the image implies that, and games count on it to keep their CPU at most a window's worth
    // of frames ahead of the GPU. This game's frame bookkeeping underflowed when the CPU ran further ahead during
    // pipeline-build stalls (its GPU progress counter fell behind the fences it waited for). So the acquire waits for
    // the newest submit of that present, and the sync means that fence (fenced = 1); an image never presented is
    // free at once (fenced = 3 with fence 0).
    uint64_t f = idx < 4 ? o->fence[idx] : 0;
    // OOT_GPU_AHEAD=<n> (default 1): the acquire also waits until the GPU completed every submit made before the
    // n-th last acquire, so the CPU keeps at most n frames of work queued ahead of the GPU whatever the window's
    // image count. This game's pool of GPU timer queries holds three per profiler and refills only from queries whose
    // submit completed; at a frame's first pop the submits of two frames ago must be done, which on hardware the
    // GPU's pace provides and a replay stalled by pipeline builds does not (the crash in main+0x115980). 0 serialises
    // CPU and GPU frames; a larger n loosens the bound.
    static int ahead = -1;
    if (ahead < 0) {
        const char *e = cfg_get("OOT_GPU_AHEAD");
        ahead = e && *e ? atoi(e) : 1;
        if (ahead < 0 || ahead > 3) ahead = 1;
    }
    // Below 60 with ap_var the CPU starts a frame only once the GPU finished the previous one (ahead 0). With the CPU a
    // frame ahead at an uneven rate the game's frames went black (NaN from the scene pass on, spread by bloom and the
    // upscaler): the replay's VRAM mirror takes the guest's bytes and writes the GPU's results back when the GPU runs
    // a submission, not when it is submitted, and a CPU already on the next frame races both (docs/level.md,
    // 2026-11-10). Forest Temple walk at a free rate: 144 isolated black of 2833 presents at 47 fps with ahead 1, 0 of
    // 2224 at 37 fps with ahead 0; at a steady 60 the overlap is kept, where it is worth 60 against 44 fps.
    int eff = ap_mode == -1 && ap_var && ap_ticks == 2 ? 0 : ahead;
    uint64_t now_f = nvn_fence_last();
    if (o->acquires >= (uint64_t)eff) {
        uint64_t g = o->acq[(o->acquires - (uint64_t)eff) & 3];   // 0 for "at this acquire"
        if (eff == 0) g = now_f;
        if (g > f) f = g;
    }
    o->acq[o->acquires++ & 3] = now_f;
    if (f) {
        const GfxBackend *b = gfx_backend();
        if (b->fence_done() < f) {
            uint64_t p0 = perf_begin();
            b->fence_wait(f, ~0ull);
            perf_end(PERF_PACE, p0);
        }
        b->cpu_synced(f);
    }
    InterlockedAdd64(&ap_wait_ns, (LONG64)(kern_now_ns() - w0));
    if (s) {
        s->fenced = f ? 1 : 3;
        s->fence = f;
    }
    ret_x(c, NVN_WINDOW_ACQUIRE_TEXTURE_RESULT_SUCCESS);
}

// void nvnQueuePresentTexture(NVNqueue *q, NVNwindow *w, int index): queues the copy and returns at once. The display
// time comes from the pacer: the back end's present thread holds the host present until then (back-edge pacing, as the
// Switch's display flips at vblank), so the present cadence does not follow the replay time; one period later the
// image is free for the next acquire. Added latency: the slack of the frame (period minus its work), as on the Switch.
NVN_API(nvnQueuePresentTexture) {
    win_t *o = arg_p(c, 1);
    int idx = (int)arg_x(c, 2);
    movie_tick(c);   // ov_movie.c: hand over decoded movie frames that are due; needs the core, so before the wait
    NVN_BLOCKING();
    if (o->magic != NVN_WIN_MAGIC || idx < 0 || idx >= o->ntex || idx >= 4 || !o->tex[idx])
        rt_fatal("nvn: QueuePresentTexture of image %d on window %p", idx, (void *)o);
    o->presents++;
    const tex_t *t = (const tex_t *)o->tex[idx];
    uint64_t now0 = kern_now_ns();
    ap_present(now0);
    uint64_t period = present_period(o), now = now0;
    uint64_t slot = now + pace(&o->pace, now, period);
    gfx_backend()->present(t, o->crop, slot);
    o->ticket[idx] = o->presents;
    o->avail[idx] = slot + period;
    o->fence[idx] = nvn_fence_last();   // the frame rendered into this image was submitted before its present
    frame_step_present(slot, o->interval);   // frame_rate.c: the real-time step follows the display times
    rt_frame_presented(t, o->presents);
}
