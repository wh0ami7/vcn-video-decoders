#include "vcnav1.h"

#include <CoreFoundation/CoreFoundation.h>
#include <CoreVideo/CoreVideo.h>
#include <IOKit/IOKitLib.h>
#include <dlfcn.h>
#include <mach-o/dyld.h>
#include <mach-o/loader.h>
#include <mach/mach_time.h>
#include <pthread.h>
#include <stdio.h>
#include <stdlib.h>
#include <string.h>
#include <unistd.h>

#include "avd.h"

int vcnav1_debug = 0;
int vcnav1_gpu_armed = 0;
#define DBG(...)                                                \
  do {                                                          \
    if (vcnav1_debug) fprintf(stderr, "[vcnav1] " __VA_ARGS__); \
  } while (0)

#define VCN_MODE_VCN0 4
#define NUM_DPB 9
#define NUM_BS 4
#define BS_SIZE 0x1800000u
#define SEQ_BYTES 2048
#define FRAME_BYTES 4096
#define BSINFO_BYTES (20 + 64 * 512 + 64)

// Parameter block consumed by AvdVcnAv1DecDataProcessor (recovered layout).
typedef struct {
  void* seq;              // +0
  void* frame;            // +8
  uint32_t curr_pic_idx;  // +16
  uint32_t pad0;
  IOSurfaceRef output;        // +24
  uint32_t ref_frame_map[8];  // +32
  uint32_t frame_refs[7];     // +64
  uint32_t pad1;              // +92
  void* bsinfo;               // +96
  uint8_t reserved[160];
} AV1Params;

typedef struct {
  void* refcon;
  uint32_t pollMs;  // driver completion-poll interval (ms)
  uint32_t wait;
  uint32_t status, status2;
} AVD_QueryEntry;
typedef struct {
  uint32_t count, pad;
  AVD_QueryEntry* entries;
} AVD_QueryList;

struct VcnAV1 {
  AVD_Accelerator* accel;
  void* drv;
  void* ctx;
  void* bsAddr[NUM_BS];
  int bsNext;
  uint32_t maxW, maxH;
  AV1Parser parser;
  CVPixelBufferRef dpb[NUM_DPB];  // last picture decoded into each DPB slot
                                  // (kept for show_existing_frame)
  int dpbRefs[NUM_DPB];           // number of reference slots pointing here
  uint8_t *seq, *frame, *bsinfo;
  char err[256];
  VcnAV1OutputFn out;
  void* outCtx;
  int64_t tag;
  CVPixelBufferPoolRef
      pool;  // decode targets; references live in the driver's internal DPB
  uint32_t poolW, poolH;
  bool poolTen;
};

static io_service_t find_accelerator(void) {
  io_iterator_t it;
  if (IOServiceGetMatchingServices(kIOMainPortDefault,
                                   IOServiceMatching("IOAccelerator"), &it))
    return 0;
  io_service_t s, found = 0;
  while ((s = IOIteratorNext(it))) {
    CFTypeRef codec =
        IORegistryEntryCreateCFProperty(s, CFSTR("IOGVACodec"), NULL, 0);
    if (codec) {
      CFRelease(codec);
      found = s;
      break;
    }
    IOObjectRelease(s);
  }
  IOObjectRelease(it);
  return found;
}

#define FN(name) ((AVD_##name##_fn)d->accel->fn[AVD_FN_##name])

// The parameter layouts were recovered from (and validated on the GPU against)
// these exact builds of AMDRadeonVADriver2. Another build may lay them out
// differently, and a wrong VCN message can hang the GPU, so refuse to run
// elsewhere unless VCNAV1_ALLOW_UNVALIDATED_DRIVER=1 (after a dry run).
static const char* const kValidatedDrivers[] = {
    "8D3BA61E7BC73BDFADB3A7866360B6DE",  // macOS 26.7.1 (25G241)
    "5D90FED3BCBF34759F4B8FC00026D3AB",  // macOS 15.8.2 (24H232) and 15.8.3
                                         // (24H241, same binary): compared in
                                         // IDA against 26.7.1, same AV1 path
    "1181E2CA31B33DF090E23AE70552D753",  // macOS 26.7.2 (25G332) and 26.7.3
                                         // (25G342, same binary): compared in
                                         // IDA against 26.7.1, same code
};

static bool driver_uuid(char out[33]) {
  for (uint32_t i = 0; i < _dyld_image_count(); i++) {
    if (!strstr(_dyld_get_image_name(i), "AMDRadeonVADriver2")) continue;
    const struct mach_header_64* h = (const void*)_dyld_get_image_header(i);
    const struct load_command* lc = (const void*)(h + 1);
    for (uint32_t k = 0; k < h->ncmds;
         k++, lc = (const void*)((const char*)lc + lc->cmdsize))
      if (lc->cmd == LC_UUID) {
        for (int j = 0; j < 16; j++)
          snprintf(out + 2 * j, 3, "%02X",
                   ((const struct uuid_command*)lc)->uuid[j]);
        return true;
      }
  }
  return false;
}

static CFNumberRef cfnum(long long v) {
  return CFNumberCreate(NULL, kCFNumberLongLongType, &v);
}
// Pixel buffer attributes whose IOSurfaces have the layout validated on the
// VCN: pitch aligned to 256, height padded to 64, UV plane offset aligned to
// 4096.
CFDictionaryRef vcnav1_copy_pixel_buffer_attributes(uint32_t w, uint32_t h,
                                                    bool tenBit) {
  CFMutableDictionaryRef a =
      CFDictionaryCreateMutable(NULL, 0, &kCFTypeDictionaryKeyCallBacks,
                                &kCFTypeDictionaryValueCallBacks);
  CFMutableDictionaryRef io =
      CFDictionaryCreateMutable(NULL, 0, &kCFTypeDictionaryKeyCallBacks,
                                &kCFTypeDictionaryValueCallBacks);
  CFNumberRef n;
#define PUT(k, v) (n = cfnum(v), CFDictionarySetValue(a, k, n), CFRelease(n))
  PUT(kCVPixelBufferPixelFormatTypeKey,
      tenBit ? kCVPixelFormatType_420YpCbCr10BiPlanarVideoRange
             : kCVPixelFormatType_420YpCbCr8BiPlanarVideoRange);
  PUT(kCVPixelBufferWidthKey, w);
  PUT(kCVPixelBufferHeightKey, h);
  PUT(kCVPixelBufferBytesPerRowAlignmentKey, 256);
  PUT(kCVPixelBufferPlaneAlignmentKey, 4096);
  uint32_t padH = (h + 63) & ~63u, pitch = (w + 255) & ~255u;
  PUT(kCVPixelBufferExtendedPixelsBottomKey, padH - h);
  // The driver's AV1 path leaves the picture blank, with no error, when the
  // padded height is larger than the pitch (portrait video). Widen the rows
  // until the pitch reaches the padded height.
  if (padH > pitch)
    PUT(kCVPixelBufferExtendedPixelsRightKey, ((padH + 255) & ~255u) - w);
#undef PUT
  CFDictionarySetValue(a, kCVPixelBufferIOSurfacePropertiesKey, io);
  CFDictionarySetValue(a, kCVPixelBufferMetalCompatibilityKey, kCFBooleanTrue);
  CFRelease(io);
  return a;
}
static CVPixelBufferRef new_target(VcnAV1* d, uint32_t w, uint32_t h,
                                   bool tenBit) {
  if (d->pool && (d->poolW != w || d->poolH != h || d->poolTen != tenBit)) {
    CVPixelBufferPoolRelease(d->pool);
    d->pool = NULL;
  }
  if (!d->pool) {
    CFDictionaryRef attrs = vcnav1_copy_pixel_buffer_attributes(w, h, tenBit);
    CVReturn r = CVPixelBufferPoolCreate(NULL, NULL, attrs, &d->pool);
    CFRelease(attrs);
    if (r) {
      d->pool = NULL;
      return NULL;
    }
    d->poolW = w;
    d->poolH = h;
    d->poolTen = tenBit;
  }
  CVPixelBufferRef pb = NULL;
  if (CVPixelBufferPoolCreatePixelBuffer(NULL, d->pool, &pb)) return NULL;
  return pb;
}
VcnAV1* vcnav1_create(uint32_t maxWidth, uint32_t maxHeight, char* err,
                      size_t errLen) {
  VcnAV1* d = calloc(1, sizeof(*d));
  if (!d) {
    if (err && errLen) snprintf(err, errLen, "out of memory");
    return NULL;
  }
  d->maxW = maxWidth;
  d->maxH = maxHeight;
  av1_parser_init(&d->parser);
  d->seq = calloc(1, SEQ_BYTES);
  d->frame = calloc(1, FRAME_BYTES);
  d->bsinfo = calloc(1, BSINFO_BYTES);
#define FAIL(...)                                          \
  do {                                                     \
    if (err && errLen) snprintf(err, errLen, __VA_ARGS__); \
    vcnav1_destroy(d);                                     \
    return NULL;                                           \
  } while (0)
  if (!d->seq || !d->frame || !d->bsinfo) FAIL("out of memory");
  void* lib = dlopen(AVD_DRIVER_PATH, RTLD_NOW | RTLD_LOCAL);
  if (!lib) FAIL("dlopen driver: %s", dlerror());
  char uuid[33] = "unknown";
  bool validated = false;
  driver_uuid(uuid);
  for (size_t i = 0; i < sizeof(kValidatedDrivers) / sizeof(*kValidatedDrivers);
       i++)
    if (!strcmp(uuid, kValidatedDrivers[i])) validated = true;
  const char* ov = getenv("VCNAV1_ALLOW_UNVALIDATED_DRIVER");
  if (!validated && !(ov && !strcmp(ov, "1")))
    FAIL(
        "AMDRadeonVADriver2 build %s not validated (dry-run it, then set "
        "VCNAV1_ALLOW_UNVALIDATED_DRIVER=1)",
        uuid);
  DBG("driver %s%s\n", uuid, validated ? " (validated)" : " (UNVALIDATED)");
  AVD_CreateAVDAccelerator_fn create =
      (AVD_CreateAVDAccelerator_fn)dlsym(lib, "AVD_CreateAVDAccelerator");
  if (!create) FAIL("no AVD_CreateAVDAccelerator");
  io_service_t svc = find_accelerator();
  if (!svc) FAIL("no AMD accelerator");
  uint32_t services[8] = {svc};
  AVD_AcceleratorCreate ac = {
      .index = 0, .services = services, .validMask = 0xffffffff};
  uint8_t info[256] = {0};
  int r = create(&d->accel, &ac, info);
  if (r || !d->accel) FAIL("CreateAVDAccelerator %d", r);
  AVD_DriverCreate dc = {.initFlags = 0, .accel = d->accel};
  r = FN(CreateDriver)(&d->drv, &dc);
  if (r) FAIL("CreateDriver %d", r);
  AVD_BitstreamPool pool = {.type = 0,
                            .size = BS_SIZE,
                            .format = 0x72617762,
                            .one = 1,
                            .count = NUM_BS,
                            .addressesOut = d->bsAddr,
                            .eight = 8,
                            .five = 5};
  r = FN(AllocateBitstreamBufferPool)(d->drv, &pool);
  if (r || !d->bsAddr[0]) FAIL("AllocateBitstreamBufferPool %d", r);
  AVD_ContextList list = {0};
  void* ctxOut[2] = {0};
  AVD_FunctionInfo* fis[1] = {&list.inlineInfo};
  list.count = 1;
  list.functions = fis;
  list.contextsOut = ctxOut;
  // mode 3/5 => VAVcnDecoder::Init(1) => second VCN instance (VCN1Dec), which
  // has NO AV1 on Navi21 and hangs the GPU. Mode 4 (what AppleGVA uses for
  // H.264) => Init(0) => VCN0Dec.
  list.inlineInfo = (AVD_FunctionInfo){.kind = 1,
                                       .function = AVD_FUNC_AV1,
                                       .mode = VCN_MODE_VCN0,
                                       .pixelRate = maxWidth * maxHeight * 60,
                                       .width = maxWidth,
                                       .height = maxHeight,
                                       .inFormat = 0x72617762,
                                       .inFormatCount = 1,
                                       .outFormat = 0x4e563132,
                                       .outFormatCount = 1};
  AVD_DriverContextInit ci = {.list = &list};
  r = FN(CreateContexts)(d->drv, &ci);
  if (r || !ctxOut[0]) FAIL("CreateContexts(AV1) %d", r);
  d->ctx = ctxOut[0];
  DBG("created: drv=%p ctx=%p bs=%p\n", d->drv, d->ctx, d->bsAddr[0]);
  return d;
}

void vcnav1_destroy(VcnAV1* d) {
  if (!d) return;
  if (d->ctx && d->drv && d->accel) {
    void* ctxs[1] = {d->ctx};
    AVD_DriverContextDelete del = {.count = 1, .contexts = ctxs};
    FN(DeleteContexts)(d->drv, &del);
  }
  if (d->drv && d->accel) {
    FN(FreeBitstreamBufferPool)(d->drv, 0);
    FN(DeleteDriver)(d->drv);
  }
  for (int i = 0; i < NUM_DPB; i++)
    if (d->dpb[i]) CVPixelBufferRelease(d->dpb[i]);
  if (d->pool) CVPixelBufferPoolRelease(d->pool);
  av1_parser_free(&d->parser);
  free(d->seq);
  free(d->frame);
  free(d->bsinfo);
  free(d);
}

const char* vcnav1_last_error(VcnAV1* d) { return d ? d->err : ""; }

static inline void S32(uint8_t* base, int idx, int v) {
  ((int32_t*)base)[idx] = v;
}
static inline void F32(uint8_t* base, int off, int v) {
  *(int32_t*)(base + off) = v;
}

static void pack_seq(VcnAV1* d) {
  const AV1Seq* s = &d->parser.seq;
  uint8_t* q = d->seq;
  memset(q, 0, SEQ_BYTES);
  S32(q, 0, s->seq_profile);
  S32(q, 1, s->still_picture);
  S32(q, 2, s->reduced_still_picture_header);
  S32(q, 305, s->max_frame_width_minus_1);
  S32(q, 306, s->max_frame_height_minus_1);
  S32(q, 307, s->frame_id_numbers_present_flag);
  S32(q, 308, s->delta_frame_id_length_minus_2);
  S32(q, 309, s->additional_frame_id_length_minus_1);
  S32(q, 310, s->use_128x128_superblock);
  S32(q, 311, s->enable_filter_intra);
  S32(q, 312, s->enable_intra_edge_filter);
  S32(q, 313, s->enable_interintra_compound);
  S32(q, 314, s->enable_masked_compound);
  S32(q, 315, s->enable_warped_motion);
  S32(q, 316, s->enable_dual_filter);
  S32(q, 317, s->enable_order_hint);
  S32(q, 318, s->enable_jnt_comp);
  S32(q, 319, s->enable_ref_frame_mvs);
  S32(q, 320, s->seq_choose_screen_content_tools);
  S32(q, 321, s->seq_force_screen_content_tools);
  S32(q, 322, s->seq_choose_integer_mv);
  S32(q, 323, s->seq_force_integer_mv);
  S32(q, 324, s->order_hint_bits_minus_1);
  S32(q, 325, s->OrderHintBits);
  S32(q, 326, s->enable_superres);
  S32(q, 327, s->enable_cdef);
  S32(q, 328, s->enable_restoration);
  S32(q, 329, s->high_bitdepth);
  S32(q, 330, s->twelve_bit);
  S32(q, 331, s->BitDepth);
  S32(q, 332, s->mono_chrome);
}

static void pack_frame(VcnAV1* d) {
  const AV1Frame* h = &d->parser.fh;
  uint8_t* q = d->frame;
  memset(q, 0, FRAME_BYTES);
  F32(q, 0, h->show_existing_frame);
  F32(q, 4, h->frame_to_show_map_idx);
  F32(q, 16, h->frame_type);
  F32(q, 20, h->FrameIsIntra);
  F32(q, 24, h->show_frame);
  F32(q, 28, h->showable_frame);
  F32(q, 32, h->error_resilient_mode);
  F32(q, 36, h->disable_cdf_update);
  F32(q, 40, h->allow_screen_content_tools);
  F32(q, 44, h->force_integer_mv);
  F32(q, 48, h->current_frame_id);
  F32(q, 52, h->frame_size_override_flag);
  F32(q, 64, h->order_hint);
  F32(q, 100, h->primary_ref_frame);
  F32(q, 236, h->refresh_frame_flags);
  F32(q, 304, h->frame_width_minus_1);
  F32(q, 308, h->frame_height_minus_1);
  F32(q, 312, h->FrameWidth);
  F32(q, 320, h->FrameHeight);
  F32(q, 324, h->UpscaledWidth);
  F32(q, 328, h->use_superres);
  F32(q, 332, h->SuperresDenom);
  F32(q, 364, h->allow_intrabc);
  F32(q, 440, h->allow_high_precision_mv);
  F32(q, 448, h->interpolation_filter);
  F32(q, 452, h->is_motion_mode_switchable);
  F32(q, 456, h->use_ref_frame_mvs);
  F32(q, 460, h->disable_frame_end_update_cdf);
  F32(q, 464, h->uniform_tile_spacing_flag);
  F32(q, 468, h->TileColsLog2);
  F32(q, 472, h->TileRowsLog2);
  for (int i = 0; i <= h->TileCols && i <= 64; i++)
    F32(q, 484 + 4 * i, h->MiColStarts[i]);
  for (int i = 0; i <= h->TileRows && i <= 64; i++)
    F32(q, 744 + 4 * i, h->MiRowStarts[i]);
  F32(q, 1004, h->TileCols);
  F32(q, 1008, h->TileRows);
  F32(q, 1020, h->context_update_tile_id);
  F32(q, 1024, h->TileSizeBytes);
  F32(q, 1032, h->base_q_idx);
  F32(q, 1044, h->DeltaQYDc);
  F32(q, 1048, h->diff_uv_delta);
  F32(q, 1052, h->DeltaQUDc);
  F32(q, 1056, h->DeltaQUAc);
  F32(q, 1060, h->DeltaQVDc);
  F32(q, 1064, h->DeltaQVAc);
  F32(q, 1068, h->using_qmatrix);
  F32(q, 1072, h->qm_y);
  F32(q, 1076, h->qm_u);
  F32(q, 1080, h->qm_v);
  F32(q, 1084, h->segmentation_enabled);
  F32(q, 1088, h->segmentation_update_map);
  F32(q, 1092, h->segmentation_temporal_update);
  F32(q, 1096, h->segmentation_update_data);
  for (int i = 0; i < 8; i++)
    for (int j = 0; j < 8; j++) {
      F32(q, 1104 + 32 * i + 4 * j, h->FeatureEnabled[i][j]);
      *(int16_t*)(q + 1364 + 16 * i + 2 * j) = (int16_t)h->FeatureData[i][j];
    }
  F32(q, 1500, h->delta_q_present);
  F32(q, 1504, h->delta_q_res);
  F32(q, 1508, h->delta_lf_present);
  F32(q, 1512, h->delta_lf_res);
  F32(q, 1516, h->delta_lf_multi);
  for (int i = 0; i < 4; i++) F32(q, 1656 + 4 * i, h->loop_filter_level[i]);
  F32(q, 1672, h->loop_filter_sharpness);
  F32(q, 1676, h->loop_filter_delta_enabled);
  F32(q, 1680, h->loop_filter_delta_update);
  for (int i = 0; i < 8; i++)
    F32(q, 1688 + 4 * i, h->loop_filter_ref_deltas[i]);
  F32(q, 1724, h->loop_filter_mode_deltas[0]);
  F32(q, 1728, h->loop_filter_mode_deltas[1]);
  F32(q, 1736, h->cdef_bits);
  for (int i = 0; i < 8; i++) {
    // driver computes (f[1772]<<6)|f[1740]; give it the VCN-ready (pri<<2)|sec
    // value
    F32(q, 1740 + 4 * i, (h->cdef_y_pri[i] << 2) | (h->cdef_y_sec[i] & 3));
    F32(q, 1772 + 4 * i, 0);
    F32(q, 1804 + 4 * i, (h->cdef_uv_pri[i] << 2) | (h->cdef_uv_sec[i] & 3));
    F32(q, 1836 + 4 * i, 0);
  }
  F32(q, 1868, h->CdefDamping);
  for (int i = 0; i < 3; i++) {
    F32(q, 1872 + 4 * i, h->FrameRestorationType[i]);
    F32(q, 1900 + 4 * i, h->LoopRestorationSize[i]);
  }
  F32(q, 1920, h->TxMode);
  F32(q, 1924, h->reference_select);
  F32(q, 1936, h->skip_mode_present);
  F32(q, 1940, h->allow_warped_motion);
  F32(q, 1944, h->reduced_tx_set);
  for (int ref = 1; ref <= 7; ref++) {
    F32(q, 1952 + 4 * (ref - 1), h->gm_type[ref]);
    for (int j = 0; j < 6; j++)
      F32(q, 2004 + 24 * (ref - 1) + 4 * j, h->gm_params[ref][j]);
  }
  const AV1FilmGrain* g = &h->film_grain;
  F32(q, 2376, g->apply_grain);
  F32(q, 2380, g->grain_seed);
  F32(q, 2384, g->update_grain);
  F32(q, 2388, g->film_grain_params_ref_idx);
  F32(q, 2392, g->num_y_points);
  for (int i = 0; i < 14; i++) {
    F32(q, 2396 + 4 * i, g->point_y_value[i]);
    F32(q, 2452 + 4 * i, g->point_y_scaling[i]);
  }
  F32(q, 2508, g->chroma_scaling_from_luma);
  F32(q, 2512, g->num_cb_points);
  F32(q, 2516, g->num_cr_points);
  for (int i = 0; i < 10; i++) {
    F32(q, 2520 + 4 * i, g->point_cb_value[i]);
    F32(q, 2560 + 4 * i, g->point_cb_scaling[i]);
    F32(q, 2600 + 4 * i, g->point_cr_value[i]);
    F32(q, 2640 + 4 * i, g->point_cr_scaling[i]);
  }
  F32(q, 2680, g->grain_scaling_minus_8);
  F32(q, 2684, g->ar_coeff_lag);
  for (int i = 0; i < 24; i++) F32(q, 2688 + 4 * i, g->ar_coeffs_y_plus_128[i]);
  for (int i = 0; i < 25; i++) {
    F32(q, 2784 + 4 * i, g->ar_coeffs_cb_plus_128[i]);
    F32(q, 2884 + 4 * i, g->ar_coeffs_cr_plus_128[i]);
  }
  F32(q, 2984, g->ar_coeff_shift_minus_6);
  F32(q, 2988, g->grain_scale_shift);
  F32(q, 2992, g->cb_mult);
  F32(q, 2996, g->cb_luma_mult);
  F32(q, 3000, g->cb_offset);
  F32(q, 3004, g->cr_mult);
  F32(q, 3008, g->cr_luma_mult);
  F32(q, 3012, g->cr_offset);
  F32(q, 3016, g->overlap_flag);
  F32(q, 3020, g->clip_to_restricted_range);
}

static int alloc_dpb_slot(VcnAV1* d) {
  for (int i = 0; i < NUM_DPB; i++)
    if (d->dpbRefs[i] == 0) return i;
  return -1;
}

static void release_slot_refs(VcnAV1* d) {
  memset(d->dpbRefs, 0, sizeof(d->dpbRefs));
  for (int i = 0; i < 8; i++) {
    int s = d->parser.ref[i].dpb_slot;
    if (s >= 0 && d->parser.ref[i].valid) d->dpbRefs[s]++;
  }
}

// The dry-run lldb script breaks here and verifies its kernel-submission trap
// is armed.
__attribute__((noinline)) void vcnav1_dryrun_checkpoint(const AV1Params* prm) {
  __asm__ volatile("" ::"r"(prm) : "memory");
}
static double tnow_ms(void) {
  static mach_timebase_info_data_t tb;
  if (!tb.denom) mach_timebase_info(&tb);
  return (double)mach_absolute_time() * tb.numer / tb.denom / 1e6;
}
static int timing = -1;
static double t_sched, t_wait;
static int submit(VcnAV1* d, AV1Params* prm) {
  const char* arm = getenv("VCNAV1_ALLOW_GPU");
  if (!vcnav1_gpu_armed && (!arm || strcmp(arm, "yes-i-know-it-can-hang"))) {
    snprintf(d->err, sizeof(d->err),
             "GPU submission disabled (set VCNAV1_ALLOW_GPU)");
    return -1;
  }
  vcnav1_dryrun_checkpoint(prm);
  AVD_CmdInfo cmd = {.kind = 1,
                     .function = AVD_FUNC_AV1,
                     .mode = VCN_MODE_VCN0,
                     .context = d->ctx,
                     .params = prm};
  AVD_CmdInfo* cmds[1] = {&cmd};
  AVD_CmdList list = {.count = 1, .cmds = cmds};
  void* refcons[1] = {0};
  AVD_RefConList rl = {.count = 1, .refcons = refcons};
  double t0 = tnow_ms();
  int r = FN(ScheduleAVDCommands)(d->drv, &list, &rl);
  double t1 = tnow_ms();
  if (r) {
    snprintf(d->err, sizeof(d->err), "ScheduleAVDCommands %d", r);
    return -1;
  }
  static int qmode = -1;
  // Third field of the query entry is the driver's completion-poll interval in
  // ms: AppleGVA's 5 adds ~5 ms of latency per frame; 1 measured 2.5 ms average
  // wait vs 5.7 ms, bit-exact.
  if (qmode < 0) {
    // Env-derived poll interval: reject non-digits / out-of-range (mem:security).
    const char* qs = getenv("VCNAV1_QMODE");
    char* end = NULL;
    long v = qs ? strtol(qs, &end, 10) : 1;
    if (!qs || end == qs || *end || v < 1 || v > 100) v = 1;
    qmode = (int)v;
  }
  AVD_QueryEntry qe = {
      .refcon = refcons[0], .pollMs = (uint32_t)qmode, .wait = 1};
  AVD_QueryList ql = {.count = 1, .entries = &qe};
  r = FN(QueryAVDCommandStatus)(d->drv, &ql);
  t_sched = t1 - t0;
  t_wait = tnow_ms() - t1;
  DBG("query r=%d status=%u/%u\n", r, qe.status, qe.status2);
  if (r) {
    snprintf(d->err, sizeof(d->err), "QueryAVDCommandStatus %d", r);
    return -1;
  }
  return 0;
}

static int on_frame(void* vctx, AV1Parser* p, AV1ParseResult kind) {
  VcnAV1* d = vctx;
  const AV1Frame* h = &p->fh;
  if (kind == AV1_PARSE_SHOW_EXISTING) {
    AV1RefSlot* r = &p->ref[h->frame_to_show_map_idx];
    if (r->dpb_slot >= 0 && d->dpb[r->dpb_slot] && d->out)
      d->out(d->outCtx, d->dpb[r->dpb_slot], p, d->tag);
    if (h->frame_type == AV1_KEY_FRAME) {
      av1_reference_update(p, r->dpb_slot);
      release_slot_refs(d);
    }
    return 0;
  }
  if (timing < 0) timing = getenv("VCNAV1_TIMING") != NULL;
  double tf0 = timing ? tnow_ms() : 0;
  bool tenBit = p->seq.BitDepth > 8;
  uint32_t w = h->UpscaledWidth, hh = h->FrameHeight;
  int slot = alloc_dpb_slot(d);
  if (slot < 0) {
    snprintf(d->err, sizeof(d->err), "no free DPB slot");
    return -1;
  }
  // Fresh decode target per picture: the consumer may still hold earlier ones.
  CVPixelBufferRef target = new_target(d, w, hh, tenBit);
  if (!target) {
    snprintf(d->err, sizeof(d->err), "no pixel buffer for %ux%u", w, hh);
    return -1;
  }
  if (d->dpb[slot]) CVPixelBufferRelease(d->dpb[slot]);
  d->dpb[slot] = target;
  pack_seq(d);
  pack_frame(d);
  // bitstream: concatenated tile data
  int bi = d->bsNext;
  d->bsNext = (d->bsNext + 1) % NUM_BS;
  if (p->tile_data_size > BS_SIZE - 256) {
    snprintf(d->err, sizeof(d->err), "frame too big");
    return -1;
  }
  memcpy(d->bsAddr[bi], p->tile_data, p->tile_data_size);
  memset((uint8_t*)d->bsAddr[bi] + p->tile_data_size, 0, 256);
  memset(d->bsinfo, 0, BSINFO_BYTES);
  *(uint32_t*)(d->bsinfo + 0) = bi;
  *(uint32_t*)(d->bsinfo + 16) = (uint32_t)((p->tile_data_size + 127) & ~127u);
  for (int i = 0; i < p->num_tiles; i++) {
    const AV1Tile* t = &p->tiles[i];
    if (t->row < 0 || t->row >= 64 || t->col < 0 || t->col >= 64) {
      snprintf(d->err, sizeof(d->err), "tile index out of range");
      return -1;
    }
    uint32_t* e = (uint32_t*)(d->bsinfo + 20 + 512 * t->row + 8 * t->col);
    e[0] = t->offset;
    e[1] = t->size;
  }
  AV1Params prm;
  memset(&prm, 0, sizeof(prm));
  prm.seq = d->seq;
  prm.frame = d->frame;
  prm.curr_pic_idx = slot;
  prm.output = CVPixelBufferGetIOSurface(d->dpb[slot]);
  for (int i = 0; i < 8; i++)
    prm.ref_frame_map[i] = p->ref[i].dpb_slot >= 0 ? p->ref[i].dpb_slot : 0x7f;
  for (int i = 0; i < 7; i++) {
    int s = h->FrameIsIntra ? -1 : p->ref[h->ref_frame_idx[i]].dpb_slot;
    prm.frame_refs[i] = s >= 0 ? s : 0x7f;
  }
  prm.bsinfo = d->bsinfo;
  DBG("frame type=%d show=%d %dx%d q=%d tiles=%dx%d bytes=%zu slot=%d "
      "refresh=%02x\n",
      h->frame_type, h->show_frame, w, hh, h->base_q_idx, h->TileCols,
      h->TileRows, p->tile_data_size, slot, h->refresh_frame_flags);
  double tf1 = timing ? tnow_ms() : 0;
  if (submit(d, &prm)) return -1;
  if (timing)
    fprintf(stderr, "timing bytes=%zu prep=%.2f sched=%.2f wait=%.2f\n",
            p->tile_data_size, tf1 - tf0, t_sched, t_wait);
  av1_reference_update(p, slot);
  release_slot_refs(d);
  if (h->show_frame && d->out) {
    d->out(d->outCtx, d->dpb[slot], p, d->tag);
  }
  return 0;
}

int vcnav1_configure(VcnAV1* d, const uint8_t* obus, size_t size) {
  return av1_parse_temporal_unit(&d->parser, obus, size, on_frame, d);
}

int vcnav1_decode(VcnAV1* d, const uint8_t* tu, size_t size, int64_t userTag,
                  VcnAV1OutputFn fn, void* ctx) {
  d->out = fn;
  d->outCtx = ctx;
  d->tag = userTag;
  int r = av1_parse_temporal_unit(&d->parser, tu, size, on_frame, d);
  if (r && !d->err[0])
    snprintf(d->err, sizeof(d->err), "bitstream parse error");
  return r;
}

void vcnav1_flush(VcnAV1* d) {
  for (int i = 0; i < 8; i++) {
    d->parser.ref[i].valid = 0;
    d->parser.ref[i].dpb_slot = -1;
  }
  memset(d->dpbRefs, 0, sizeof(d->dpbRefs));
}
// Used by tools/dryrun.py: copy (possibly GPU-mapped) memory to a file from
// inside the process.
__attribute__((noinline, used)) int vcnav1_dump(const void* p, long n,
                                                const char* path) {
  // Dry-run only: refuse odd sizes and path characters that break C exprs.
  if (!p || !path || n <= 0 || n > 64 * 1024 * 1024) return -1;
  for (const unsigned char* c = (const unsigned char*)path; *c; c++) {
    if (*c < 0x20 || *c == 0x7f) return -1;
    if (!((*c >= 'A' && *c <= 'Z') || (*c >= 'a' && *c <= 'z') ||
          (*c >= '0' && *c <= '9') || *c == '.' || *c == '_' || *c == '/' ||
          *c == '-'))
      return -1;
  }
  if (strstr(path, "..")) return -1;
  FILE* f = fopen(path, "wb");
  if (!f) return -1;
  long w = (long)fwrite(p, 1, (size_t)n, f);
  fclose(f);
  return (int)w;
}
