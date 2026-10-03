# rivet — GPU backend status & hardware-verification backlog

Every GPU backend is hand-rolled `dlopen` FFI in-tree (no external wrapper crate;
builds on Windows MSVC + Linux). This tracks what's been **run on real silicon**
vs. what's only been **reviewed** and still needs a card. AV1 is the default
output codec (4:2:0, Main profile, 8- or 10-bit); H.264 / H.265 are selectable.

| Vendor | Feature | Decode | Encode (AV1) |
|--------|---------|--------|--------------|
| Intel  | `qsv`   | ✅ verified (VP9 on the CI Arc A750, bit-exact) | ✅ verified (AV1 / H.264 / H.265; VP9 profile 0 / 2 on the CI Arc A750) |
| NVIDIA | `nvidia`| ✅ verified | ⚠ by-review |
| AMD    | `amd`   | **✅ verified H.264 / HEVC (8-bit + Main 10) / AV1** on the Ryzen 9 9950X iGPU; VP9 bit-exact through the guard but **opt-in** (`RIVET_AMF_VP9=1`) after video-engine timeouts (decisions §41) | ⚠ by-review (AV1); **✅ verified H.264 / H.265** on the Ryzen 9 9950X iGPU |
| Software | `av1` (always) / `av1-sw-fallback` | ✅ AV1, bit-exact on the AOM vectors and Argon | ✅ AV1 8- and 10-bit SDR (profile 0) |
| Software | `h26x` (always) / `h26x-fallback` | ✅ H.264 + HEVC, conformance bit-exact | ✅ H.264 + H.265 8-bit, SELF + libavcodec cross-checked |
| Software | `prores` / `vp8` / `vp9` / `mpeg2` / `mpeg4` (always) | ✅ ProRes, VP8, VP9, MPEG-1/2, MPEG-4 Part 2 | ✅ ProRes, VP8, VP9 (8- and 10-bit), MPEG-2, MPEG-4 Part 2 — the only encoder for each |

---

## Intel — `qsv` ✅ COMPLETE

Hardware-verified end-to-end on a **3× Intel Arc** box (A310/A380/A750, Ubuntu
26.04, iHD 26.1.2), 2026-06-27.

- **Decode** (oneVPL, `decode/qsv_dec.rs`): H.264, HEVC, AV1, VP9; 8-bit **and**
  10-bit P010 (HEVC Main10 → AV1 `yuv420p10le` verified). Uses the oneVPL 2.x
  internal-allocation + `FrameInterface::Map` path.
- **Encode** (oneVPL AV1, `encode/qsv.rs`): AV1 8-bit + 10-bit P010, verified.
- Also verified: **multi-GPU** chunk-and-stitch across all 3 cards, the **HLS ABR
  ladder**, and **non-16-multiple rungs** (572×240, neutral-black padding so no
  green bars).

Remaining: only a nice-to-have.
- [ ] By-eye browser QA of an odd-width source — confirm no green bars when a
      player decodes the coded frame and ignores the crop.

---

## NVIDIA — `nvidia`

- **Decode** (NVDEC / CUVID, `decode/nvdec.rs`): H.264, HEVC, AV1, VP8, VP9,
  MPEG-2, MPEG-4 Part 2; 10-bit **P016**. ✅ **Verified on RTX 3090**
  (`nvdec_smoke` 17/17).
- **Encode** (NVENC AV1, `encode/nvenc.rs`): AV1 8-bit + 10-bit. ⚠ **By-review
  only** — the dev box is Ampere (RTX 3090), which has no AV1-encode silicon. The
  capability query *is* hardware-proven on the 3090 (it correctly reports "2
  codecs, none AV1" and rejects).

- [ ] **NVENC AV1 encode** end-to-end on **Ada+** (RTX 4000+ / L4 / A10G):
      correct pixels, valid `av1C`, and the 10-bit (`YUV420_10BIT`) path.

---

## AMD — `amd`

Hand-rolled AMF FFI mirroring the AMD AMF SDK headers (`decode/amf_dec.rs`,
`encode/amf.rs`), plus `amf_device.rs` (Windows DXGI/D3D11 adapter routing).

**Done (2026-06-29, on the RTX 3090 + Ryzen 9 9950X box):**
- **Windows AMD/Intel GPU detection** (WMI `Win32_VideoController`) — AMD GPUs are
  enumerated on Windows, not just via Linux sysfs.
- **Heterogeneous index space** — `GpuDevice::vendor_index` (vendor-local, for the
  hardware adapter) + a globally-unique `index` (what the user addresses), so an
  NVIDIA + AMD host no longer collides on index 0.
- **AMF multi-adapter routing** — a D3D11 device made on the chosen AMD adapter
  (`D3D11_CREATE_DEVICE_VIDEO_SUPPORT`) is handed to `InitDX11`, so AMF binds to
  the right GPU on a mixed host instead of DXGI adapter 0 (the NVIDIA card). The
  iGPU is detected as global index 1 and AMF reaches it (D3D11 create/drop test
  passes).
- **Graceful failure** — a failed AMF init no longer segfaults (the
  external-device failure path corrupts the context, so it's leaked on that cold
  path); `--decode-gpu fastest` skips an AMF-incapable GPU and an explicit pin
  errors cleanly.

**Done (2026-08-27, `agent/amf-h26x`): native H.264 / H.265 encode, and the AMF
FFI re-mirrored from the SDK v1.4.36 C headers.** The encoder's vtables had not
matched the headers (`AMFInterface` is Acquire/Release/QueryInterface, ten
`AMFPropertyStorage` slots precede every interface's methods, `InitVulkan` is on
`AMFContext1`, `AMFVariantStruct` is 24 bytes, `AMF_RESULT` is sequential —
`AMF_EOF` 23 / `AMF_INPUT_FULL` 25 / `AMF_NEED_MORE_INPUT` 44 — and the AV1
component id, several property names and enum values were off). `encode/amf/ffi.rs`
now lists every slot in header order with compile-time offset assertions, and
`test_amf_runtime_property_storage_abi` exercises the property-storage ABI on the
installed `amfrt64.dll`.

> **The Ryzen 9 9950X iGPU (`AMD Radeon(TM) Graphics`, driver 32.0.21045.5002) *is*
> AMF-capable for H.264 / H.265** (the old note called it a 9700X; `Win32_Processor`
> says 9950X). The earlier
> "`InitDX11` returns `AMF_NOT_FOUND`" was the mis-slotted vtable calling
> `GetProperty` (slot 4 in the header) where `InitDX11` was assumed, and
> `AMF_NOT_FOUND` (11) is what `GetProperty` returns for a missing name. With the
> corrected layout `AmfEncoder::new` succeeds for H.264 and H.265 on it, and AV1
> fails with `AMF_CODEC_NOT_SUPPORTED` (30), which is right for a VCN 3.1 iGPU.
> Verified there: 360p / 720p / 1080p H.264 and H.265, H.265 Main 10 (P010), HLS,
> `force_keyframe_next` (IDR + in-band SPS/PPS/VPS), one packet per frame after
> the flush fix, luma PSNR 41-53 dB vs source, ffmpeg full decode clean.

**Done (2026-09-13, `agent/amf-h26x`): AMF hardware decode, verified bit-exact.**
`decode/amf_dec.rs` and the runtime/context lifecycle (`amf_runtime.rs`) now sit
on the shared, header-checked FFI (`amf_ffi.rs`) — the same vtables the encoder
proved. One driver-specific quirk drove the port: **the UVD decoder hands back
the frames still in flight after `Drain` tagged `AMF_REPEAT` with a live buffer,
not `AMF_OK`** (only the very last one is `AMF_OK`). A decoder that treated
`AMF_REPEAT` as "nothing yet" lost the tail of every stream (58 of 60 frames).
`drain_outputs` now takes a frame whenever `QueryOutput` yields a non-null buffer
under `AMF_OK` **or** `AMF_REPEAT` — the AMF API Reference's `QueryOutput`
(`AMF_REPEAT` is "retry", and `AMF_OK` may come with a null `ppData`, so the
pointer decides), cross-checked against a standalone C++ client on the SDK
headers.

> **Verified on the Ryzen 9 9950X iGPU** (`tests/amf_decode_pixels.rs`): H.264
> (no-B and B=3), HEVC 8-bit (B=3), and HEVC Main 10 (P010 → `yuv420p10le`) each
> decode **60/60 frames byte-for-byte** equal to ffmpeg **and** to the in-tree
> `h26x` software decoders; AV1 8-bit decodes 60/60 byte-for-byte vs ffmpeg. VP9's
> component is present (in the probe caps) but no VP9 clip is generated. Through
> `rivet transcode … --decode gpu:1 --encode gpu:1` (the `nvidia` feature off) AMF
> decode engages on the iGPU with zero fallbacks and 60 frames out for H.264 /
> HEVC / Main 10. `rivet capabilities` reports amf for h264/hevc/vp9/av1, gated on
> the per-codec `CreateComponent` probe (`host_supports`). On-hardware AMF tests
> (encode + decode) serialise behind `codec::amf_hwtest::hw_lock()` — a process
> `Mutex` plus a machine-wide named mutex, since the two test binaries are
> separate processes sharing the one iGPU.

> Expect the same class of struct-layout / init-flow surprises QSV had on first
> real hardware. QSV needed: every mfx struct offsetof-verified, the MFXLoad
> dispatcher (not legacy init), an advisory Query (proceed to Init on the
> driver's spurious `-3`), LowPower=ON, and a frame-sized output buffer.

Verify:
- [ ] **AMF decode, still owed** — decode on a discrete RDNA card, and Linux
      via `AMFContext1::InitVulkan`. VP9 is opt-in (`RIVET_AMF_VP9=1`): the
      iGPU's video engine timed out during the VP9 vector runs (decisions
      §41); whether a discrete card or a newer driver does the same is open.
- [ ] **AMF H.264 / HEVC / AV1 decode after the `SubmitInput` protocol fix**
      (`AMF_REPEAT` → resubmit NULL, `AMF_DECODER_NO_FREE_SURFACES`,
      `AMF_RESOLUTION_CHANGED`): not re-run on hardware —
      `RIVET_AMF_CLIPS=<clip> cargo test -p rivet-codec --release --features amd
      --test amf_decode_pixels -- --test-threads=1`, one clip at a time, on a
      machine where a GPU timeout is acceptable.
- [ ] **NVDEC VP9 `show_existing_frame`** — CUVID returns no picture for it
      here (one frame per packet, `CUVID_PKT_ENDOFPICTURE`); find out whether
      the parser wants it differently, then trust it in `NVDEC_POLICY`.
- [ ] **AMF AV1 encode** (RDNA3+, RX 7000+) — the AV1 property sequence in
      `encode/amf/av1.rs` is by-review: names/values from `VideoEncoderAV1.h`,
      the same session flow as the validated H.26x components, the QVBR
      inversion inferred from the H.26x measurement. Needs 8-bit + P010 end to
      end, correct pixels, and a check that `Av1QvbrQualityLevel` really runs
      higher = better.
- [ ] **AMF H.264 / H.265 on a discrete Radeon** — validated on the 9950X iGPU
      (Adrenalin, 2026-08) only. A discrete RDNA2/3 card, and Linux via
      `AMFContext1::InitVulkan`, are still owed; so is a VMAF sweep of the shared
      H.26x QP anchors and of `52 - QP` as the QVBR level.
- [ ] **AMF Main 10 rate control** — constant QP because this driver ignores the
      QVBR level at 10 bits (levels 1 / 26 / 32 / 38 gave the identical
      17.3 Mbit/s stream). Re-test on a newer driver / discrete card; if QVBR
      works there, gate the CQP rule on the driver instead of on bit depth.
- [ ] **AMF QVBR bitrate ceiling** — `TargetBitrate` / `PeakBitrate` /
      `VBVBufferSize` + `EnforceHRD` are set; no encode here came near its
      ceiling, so enforcement is unmeasured.

---

## Software AV1 — `crates/av1` (`av1-sw-fallback` for encode)

The workspace's own AV1 decoder and encoder (2026-10-03), a git submodule of
[rivet-av1](https://github.com/safewords/rivet-av1), written clean-room
from the AV1 specification; they replaced rav1d and rav1e (see
[decisions.md §39](docs/decisions.md#39-av1-and-every-still-image-codec-are-the-workspaces-own-rav1e-rav1d-and-the-image-crate-are-gone)).
No system libraries, no assembly, no bindgen — the safety net for a host with
no usable encode/decode silicon, without making the build environment part of
the deployment story.

- **Decode** (`decode/av1_sw.rs`, always in the chain behind NVDEC / AMF / QSV,
  no feature): the whole specification, bit-exact on all 244 AOM test vectors
  and all 3,015 Argon conformance streams; 8/10/12-bit 4:2:0 / 4:2:2 / 4:4:4
  out, monochrome as 4:2:0 with neutral chroma, film grain applied. It runs on
  its own worker thread three temporal units ahead of the caller
  (`RIVET_AV1_DECODE_THREAD=0` decodes on the caller's thread).
- **Encode** (`encode/av1_sw.rs`, backend `av1`; reached by name or through
  `av1-sw-fallback`): profile 0, 8- and 10-bit 4:2:0, one tile (up to 4096
  wide), key and inter frames, a quality target (quantiser = 4 × the libaom
  cq-level) or an average bitrate (the crate's rate control); session `reset`
  supported.

No hardware verification is owed (there is no hardware), but the round-trip is
covered by `crates/codec/tests/software_av1_roundtrip.rs`, which encodes and
decodes a synthetic frame and checks a hard vertical edge on **every row** —
a stride or plane-origin bug shears the picture progressively down the frame
and a spot-check misses it — and end to end by
`crates/rivet/tests/new_codecs_e2e.rs` (`av1_in_software_8_and_10_bit`).

Open:
- [ ] **Decode speed.** Single-threaded scalar, about 6 megapixels/s on one
      core on streams that use the whole toolbox (~7 fps at 720p, ~3 fps at
      1080p); rivet's own encoder's output decodes at about 23 MP/s (25 fps
      at 720p). Measure with `cargo test -p rivet-codec --release --features
      av1-sw-fallback --test software_av1_roundtrip -- --ignored --nocapture
      throughput_at_720p`. The worker thread only
      overlaps the decode with conversion, scaling and encoding; the crate's
      API has no tile or frame parallelism to use beyond that. Tile threading
      and SIMD belong in `crates/av1`.
- [ ] **Encode speed and quality.** About 10 fps at 352x288 and 2 fps
      (1.9 MP/s) at 1280x720 single-threaded,
      and below rav1e's quality at the same quantiser. One tile, so nothing to
      spread over cores either.
- [ ] **HDR AV1 in software.** The encoder writes no colour description into
      the sequence header (the MP4 `colr` box carries the colour), so its
      output capability is 10-bit SDR; HDR10 / HLG AV1 still needs a GPU.
- [ ] **A forced-keyframe call in the crate.** `force_keyframe_next` starts a
      fresh encoder today, as the crate has none.

Software decode of ProRes, VP8, VP9, MPEG-1 / MPEG-2 and MPEG-4 Part 2 is
covered by the workspace's own decoders since 2026-10-02 — see [Software ProRes,
VP8, VP9, MPEG-2, MPEG-4 Part 2](#software-prores-vp8-vp9-mpeg-2-mpeg-4-part-2--clean-room-submodules)
below.

---

## Software H.264 / H.265 — `crates/h26x` (`h26x-fallback` for encode)

The workspace's own codec pair, a git submodule of
[rivet-h26x-codecs](https://github.com/safewords/rivet-h26x-codecs).
**Decode** (2026-08-18): H.264 and HEVC, bit-exact against the JVT / JCT-VC
conformance suites — since 2026-08-27 **every** stream in every suite the box
holds: JVT AVCv1+FRExt 204/204 (FMO / ASO slice groups and SP/SI slices now
decode; libavcodec refuses or misdecodes those), professional profiles 38/38,
JCT-VC HEVC v1 147/147 and RExt 49/49 (unequal luma/chroma depth, 16-bit,
extended precision, CABAC bypass alignment) — the only refusal left is H.264
data partitioning, for which no conformance stream exists. Frame- and
wavefront-threaded, SSE2→AVX-512 + NEON; always in the decode chain below the
hardware tiers. **Encode** (2026-08-27): both codecs, wired in as
`encode/h26x_sw.rs` behind `h26x-fallback` (the same policy switch as
`av1-sw-fallback`) and
always constructible by name (`TRANSCODE_ENCODER_BACKEND=h26x`). The encoder
gate (`crates/h26x/tools/verify_encode.sh`, 344 cells over 14 clips incl.
10/12-bit ones) holds seven properties per cell: SELF (our decoder reproduces
the encoder's own reconstruction byte for byte), CROSS (libavcodec agrees with
our decoder), PSNR reported, rate / CPB objectives hit where set, BOX (one
parameter set of each kind per stream), and SPEED reported. Round-trip through
rivet's adapters: `crates/codec/tests/software_h26x_roundtrip.rs`.

What the encoders have: H.264 CAVLC + CABAC, I/P/B with real motion search and
spatial direct, 16x8 / 8x16 / 8x8 partitions in P **and B** pictures, 8x8
transform, all four chroma formats, lossless, ABR rate control **with a CPB
(VUI/HRD, panic-mode re-code, `h26xhrd` checker)**; H.265 intra/P/B at 8, 10
and 12 bits, TU splits, deblocking, SAO, lossless, ABR + VBV/HRD with
panic-mode re-code, RDOQ (intra, with an early-out). SIMD (SSE2→AVX2) for the
distortion and forward-transform/quantiser kernels; a CABAC bit-cost table.
rivet uses CABAC, B pictures from `--encode-policy …:bframes=N` (non-pyramid;
the muxers carry the reorder as `ctts` v1 / `trun` v1 composition offsets),
constant QP from the shared H.26x anchor table, tools chosen by `SpeedTier`.

Open, in order of value to a transcoder:
- [x] **10-bit H.265 encode** (2026-08-27, h26x `632478a`): the H.265 encoder is
      generic over the sample type (Main 10 and 12-bit; 4:2:0/4:2:2/4:4:4), 35
      deep gate cells SELF + CROSS (libavcodec at 10/12-bit) + BOX green, 8-bit
      output byte-identical; rivet's software tier takes `yuv420p10le` for H.265.
- [ ] **H.264 High 10 encode** — every H.264 decision module is concretely `u8`
      (~190 sites across 7 files); a track-sized job. No hardware backend here
      does H.264 10-bit either, so the pipeline refuses it by name.
- [x] **VUI colour description in the h26x encoders** (2026-08-27) — both write
      `video_signal_type_present_flag` + primaries / transfer / matrix / range
      from `ColorMetadata`; `backend_output_caps(H26x)` reports HDR and the
      validator accepts HDR10/HLG on a software-only build (ffprobe-verified
      bt2020 / smpte2084 / bt2020nc in the stream). The HDR10 static metadata
      (mastering display SEI 137, content light SEI 144) is written too, in
      every IDR, byte-identical to x265's for the same values, beside the
      container's `mdcv` / `clli` — which the muxer now writes in the SEI's
      G, B, R order (it wrote R, G, B; its own reader and ffmpeg read G, B, R),
      and which the `hdr10` / `hlg` policies now keep from the source instead
      of dropping. The encoders can also write the chroma siting
      (`chroma_sample_loc_type`); rivet does not, since `ColorMetadata`
      carries none.
- [x] **Speed as a gate axis** (2026-08-27, h26x `agent/enc-speed`): every
      gate cell reports wall time and fps (property 7, `H26X_SPEED_TABLE`), with
      `tools/ab_enc.py` / `bd_rate.py` for paired A/B and BD-rate. RDOQ keeps its
      gain at a fraction of the cost: the early-out skips blocks whose last
      coefficient is ≥ 3 (BD-rate +0.000%, byte-identical streams). `f64::log2`
      was 23.5% of an all-intra H.265 encode — now a table. x86 SIMD for SAD /
      SATD / SSD and the H.265 forward DCT/DST + quantiser (identity over all
      344 cells).
- [ ] **H.264 counted shape rate** (`agent/subparts` branch, `904eabf`,
      held): pricing P-partition shapes with real bins instead of constants
      made the encoder split *less* and lost 0.03% overall — the old undercharge
      had been standing in for the missing inter residual rate. Land it together
      with a counted residual term, not before (lead's ruling, 2026-08-20).
- [x] **H.264 B partition shapes** (2026-08-27, h26x `agent/h264-bshapes`):
      Table 7-14 rows 4..21 and `B_8x8` with every sub-type, both entropy coders,
      round-tripped through the production parsers; on the cut clip 57 / 32 / 42
      macroblocks take 16x8 / 8x16 / 8x8 and the B-shape gain isolated by a
      control is −2.8% bytes / +0.06 dB.
- [x] **H.264 CPB model** (same track): SPS VUI HRD parameters, buffering-period
      / pic-timing SEI, the same panic-mode re-code as H.265 and `h26xhrd` rows
      for H.264 (`abr-64k-cpb@src_cut`, CAVLC and CABAC); mutations
      `attempts=1 → ENCODE-FAIL`, `cpb: None → HRD-FAIL` run.
- [x] **B pictures in rivet** (`agent/bframes-ctts`): `--encode-policy
      …:bframes=N` runs a non-pyramid B run on NVENC and the software H.264/H.265
      tier; each packet carries the presentation timestamp of the picture it
      codes (software: `Access::display`; NVENC: the drain walks the in-flight
      FIFO oldest-first so packets come out in decode order), and the muxers
      derive `ctts` v1 (single-file / chunked MP4) or `trun` v1 composition
      offsets (CMAF/HLS) from the rank of those timestamps
      (`container::reorder::composition_offsets`). No B pictures ⇒ no table ⇒
      byte-identical output. Verified sw/nv × h264/h265 × single/chunked/hls:
      ffprobe dts monotone, pts reordered, 120/120 frames decode clean, each
      decoded frame at its own display time (barcode); ctts-zero mutation turns
      every case red. QSV maps it to `GopRefDist` but is unverified (no Intel).
- [ ] **crates.io publish of `rivet-h26x`** — irreversible, needs an explicit
      go-ahead; the next `rivet-codec` publish depends on it (path dep 0.2.0).
- [x] **Ladder on CPU-only hosts** (2026-08-27, `agent/cpu-ladder`): the pool
      hands out software leases (N slots × threads, `RIVET_SOFTWARE_SLOTS`) when
      no card can encode the codec and the build has a software encoder; HLS and
      chunked single-file verified for h264 / h265 / av1 (chunked output decodes
      byte-identical to the serial path; 2.1–2.4× wall on a 24 s clip).

---

## Software ProRes, VP8, VP9, MPEG-2, MPEG-4 Part 2 — clean-room submodules

Five codecs written clean-room from their specifications, each in its own
repository and carried as a submodule (see
[decisions.md §34](docs/decisions.md#34-codecs-we-dont-have-we-write-clean-room-each-in-its-own-repository)).
Their decoders are always-compiled software tiers in the decode chain
(`decode/{prores,vp8,vp9,mpeg2,mpeg4}_sw.rs`, no feature); their encoders
are rivet's encoders for those codecs in every build
([decisions.md §35](docs/decisions.md#35-every-codec-rivet-decodes-it-can-encode-in-software-in-every-build)).
The VP9 encoder writes profiles 0 and 2 here (8- and 10-bit 4:2:0) with a
quality target or an average bitrate; `--video-speed` picks its tier (draft:
crate speed 2, fixed 32x32 partitions, ±8 search; standard: speed 2, fixed
16x16, ±16, about 10 fps at 352x288; archive: speed 1 with RD partition
search, ±32, about 1.7 fps at 352x288).

- [x] **ProRes decode** (2026-10-02, `crates/prores`, SMPTE RDD 36) — all six
      profiles, 4:2:2 10-bit / 4:4:4 12-bit out, interlaced woven; the only
      ProRes decoder in the chain. Alpha is decoded and dropped.
- [x] **VP8 decode** (2026-10-02, `crates/vp8`, RFC 6386) — bit-exact on all
      18 comprehensive vectors (872/872 frames); behind NVDEC.
- [x] **VP9 decode** (2026-10-02, `crates/vp9`, the VP9 bitstream
      specification) — profiles 0–3, 352/353 public vectors bit-exact; 8/10/12-bit
      4:2:0 / 4:2:2 / 4:4:4 out (4:4:0 and RGB refused); behind NVDEC / AMF / QSV.
- [x] **MPEG-2 / MPEG-1 video decode** (2026-10-02, `crates/mpeg2`, ITU-T
      H.262) — all 57 main- and 4:2:2-profile ISO/IEC 13818-4 streams decode;
      8-bit 4:2:0 / 4:2:2 out; behind NVDEC.
- [x] **MPEG-4 Part 2 decode** (2026-10-02, `crates/mpeg4`, ISO/IEC 14496-2) —
      Simple and Advanced Simple Profile, DivX packed streams, H.263 short
      header (reversible VLCs refused); 8-bit 4:2:0 out; behind NVDEC.

Open:
- [ ] **MPEG-4 Part 2 from MP4 and Matroska.** Only the AVI demuxer labels it
      (`mpeg4`, from the `strf` fourcc), and the adapter configures the decoder
      from the VOL in the stream, as AVI carries it. MP4 (`mp4v`, whose VOL is
      the `esds` decoder-specific info) and Matroska (`V_MPEG4/ISO/ASP`, VOL in
      `CodecPrivate`) are not labelled, and nothing passes that config to
      `mpeg4::Decoder::with_config`; both need doing for those files to decode.
- [ ] **AVI `DIV3` / `DIV4` are labelled `mpeg4`** (`avi/riff.rs`), but they are
      Microsoft MPEG-4 v3, not MPEG-4 Part 2: the decoder cannot take them. Label
      them something no tier claims, so the error names the real codec.
- [ ] **The other demux gaps for these codecs.** The MP4 demuxer labels VP9 and
      ProRes but not VP8 (`vp08`) or MPEG-2 in MP4; Matroska maps `V_VP8` /
      `V_VP9` but not `V_MPEG1` / `V_MPEG2` / `V_PRORES`; MPEG-TS takes stream
      type 0x02 (MPEG-2) but not 0x01 (MPEG-1); there is no MPEG program stream
      (`.mpg` / `.vob`) demuxer.
- [ ] **ProRes alpha.** Decoded and dropped: the pipeline has no alpha plane.
- [ ] **Speed.** The VP9 decoder is single-threaded scalar (about 23 frames/s at
      1080p on one core, by its README: no tile or frame threading, no SIMD);
      VP8 is scalar and single-threaded too. ProRes frames stand alone and the
      crate's `Decoder::decode` takes `&self`, but the adapter decodes one frame
      at a time (1080p 422 HQ in about 40 ms).

---

## Still images — the workspace's own codecs

Every still-image codec is the workspace's own since 2026-10-03: `crates/png`
(rivet-png), `crates/jpeg` (rivet-jpeg), `crates/webp` (rivet-webp),
`crates/imagecodecs` (rivet-gif,
rivet-bmp, rivet-tiff; a cargo workspace of its own, tested with
`cargo test --manifest-path crates/imagecodecs/Cargo.toml --workspace
--release`), and AVIF through `crates/av1` and rivet's own HEIF writer
(`crates/rivet/src/avif.rs`). The `image` crate, ravif, jpeg-encoder and
libwebp are gone.

- [ ] **AVIF beyond 8-bit 4:2:0 sRGB.** The writer encodes 8-bit 4:2:0 and
      writes no ICC profile, so AVIF output is always converted to sRGB.

---

## Filters — denoise

The spatial denoise family is implemented (`codec::filter`, `denoise=METHOD:STRENGTH`):
**bilateral, gaussian, median, mean, nlmeans, anisotropic** — selectable, 8-bit,
unit-tested + verified end-to-end (720p, 30 fps): mean/gaussian ≈ baseline,
median/bilateral fast, anisotropic ~0.09 s/frame, nlmeans ~0.84 s/frame
(offline-only). See [docs/filters/denoise.md](docs/filters/denoise.md).

Non-local means is additionally exposed with its own ffmpeg-compatible
parameters (`nlmeans=s=..:p=..:pc=..:r=..:rc=..` — patch size, research window,
separate chroma values, σ strength), evaluated through a summed-area table so
the patch size is free and only the research window drives the cost. See
[docs/filters/nlmeans.md](docs/filters/nlmeans.md).

Follow-ups:
- [x] **Deep denoise — DPIR** ([cszn/DPIR](https://github.com/cszn/DPIR), DRUNet):
      `denoise=dpir[:SIGMA][:color]` runs DRUNet on [candle](https://github.com/huggingface/candle)
      (pure Rust on the CPU; `dpir-cuda` / `dpir-cudnn` features for an NVIDIA
      GPU — chosen over tract/ONNX by measurement, ~3× faster on the CPU and a
      GPU path in the same crate). The upstream `.pth` release files are read
      directly (a legacy `torch.save` reader, no export step, downloaded once
      into the per-user cache); the model is loaded in `FilterChain::prepare`
      and shared read-only by every stream; σ is the 8-bit noise level, not a
      blend; `color` runs `drunet_color` on R'G'B'. Tiled, 8/10-bit 4:2:0,
      golden-hash + CPU-vs-CUDA tolerance tests. Numbers and the Windows
      CUDA/cuDNN build notes in [docs/filters/denoise.md](docs/filters/denoise.md#dpir--deep-denoise).
      Open: no temporal model; the network runs one tile at a time.
- [x] **Temporal denoise** — `hqdn3d` (ffmpeg's `ls:cs:lt:ct`, tables and
      16-bit arithmetic mirrored). The stateless `Arc<FilterChain>` stays the
      shared, immutable part; `FilterChain::instantiate()` gives each decode
      stream (each clip of each pump) a `FilterInstance` holding its own
      history, so rungs / ranges / splice clips never share one. Range-parallel
      decode falls back to whole for a temporal chain. See
      [docs/filters/hqdn3d.md](docs/filters/hqdn3d.md).
- [ ] **NLM-temporal** — a non-local-means variant whose research window spans
      the previous frame(s) as well; the per-stream state now exists to hold
      the frames.
- [x] **AVX2 (+ SSE4.1) denoise kernels** — bilateral, gaussian, mean, median
      and the fixed `denoise=nlmeans` (now SAT-based) run on 128- or 256-bit
      lanes, bit-identical to the scalar reference (per-kernel tests over
      random + edge planes at every tier; `RIVET_DENOISE_MAX_SIMD=none|sse41`
      caps the tier, `RIVET_DENOISE_THREADS=1` the row bands). Anisotropic
      stays scalar: its conduction is `exp` of a non-integer, which no lane
      kernel can reproduce bit-exactly against the host libm. Numbers in
      [docs/filters/denoise.md](docs/filters/denoise.md#cost).

---

## Chunk seams — fixed

Chunk boundaries used to be far more visible than the IDRs at GOP boundaries,
which read as an evenly spaced stutter. Measured with inter-frame motion
(`tblend=difference,signalstats`) against the source on 1080p content — *not*
PSNR, which misses this entirely because each frame is individually fine and it
is the join between them that jumps:

| | excess motion at chunk boundaries |
|---|---|
| originally (chunk length == GOP length) | 2.27x |
| 5-GOP chunks, no margin | 1.86x |
| **10-GOP chunks + 1-GOP margin** | **1.19x** |
| single encoder (`--seam-mode serial`) | 1.21x |
| ffmpeg `hevc_qsv -g 48` | 1.21x |

At or below the single-encoder reference, with seams every ~20 s rather than
every 2 s, and full multi-GPU parallelism retained. Three things got it there:

1. **Chunk length decoupled from GOP length.** They were the same variable, so
   every GOP boundary was a chunk boundary.
2. **One output bitstream per ring slot.** The ring shared one, so under
   sustained pressure two frames landed in it between syncs and were emitted as
   a single packet — the packet count then didn't match the frame count, which
   is what the MP4 sample table is built from. This is what made long chunks
   unusable and blocked everything else.
3. **A one-GOP lead-in margin**, encoded to warm rate control and lookahead and
   then discarded, so the chunk's first kept frame is neither a cold-start IDR
   nor preceded by a flushed tail.

Regressions to watch for, each of which caught a broken attempt: container
sample count vs decoded frame count, decoder errors, and IDR cadence. A quality
metric will not catch any of them — a stream whose chunks opened on P-frames
predicting from discarded margin frames scored *higher* mean PSNR than the
correct one, because ffmpeg conceals the missing references.

---

## Encoder session reuse (chunked multi-GPU)

`chunk_worker::encode_chunk_to_packets` builds a fresh encoder for every chunk.
That's what makes each chunk an independently decodable IDR-led GOP, which the
stitcher relies on — chunks are encoded out of order across GPUs and
concatenated — but it means ~1300 session constructions on a feature-length
file. Measured on the 3x Arc box: 89 constructions in 70 s of wall clock.

- [x] Pool sessions per (GPU, encoder config) and use `MFXVideoENCODE_Reset`
      between chunks instead of tearing the session down. Reset restarts the
      GOP, so the IDR-led guarantee survives. Needs a `reset()` on the
      `Encoder` trait, defaulting to "unsupported" so NVENC/AMF keep rebuilding
      until they grow an equivalent.

      Done 2026-08-27 (`Encoder::reset`, `encoder_worker::EncoderSessionPool`,
      one slot per ladder worker). NVENC: `NvEncReconfigureEncoder`
      (resetEncoder=1, forceIDR=1) + `NvEncGetSequenceParams` prepended to the
      new stream's first packet — the driver writes SPS/PPS once per session,
      and a reset stream's first IDR came bare (`[5]` where a fresh session
      writes `[7, 8, 5]`). Verified on an RTX 3090, H.264 and H.265, 60 s /
      30-chunk single-file: constructions 32 → 3 (2 are the capability and
      pre-flight probes), `built=1 reused=29`, every chunk boundary an IDR,
      sample count == decoded frames, zero decode errors. Each construction
      is ~115–135 ms, so ~4 s of a ~57 s run — hidden behind the decode on a
      single card, exactly as the note below predicts; the count is the
      evidence, not the wall clock. QSV: `MFXVideoENCODE_Reset` with the
      Init-time `mfxVideoParam`, by review only (no Intel here). h26x
      software: rebuild *is* the reset (7 µs). `av1` software: `reset` supported.
      `RIVET_ENCODER_POOL=off` is the same-binary control;
      `RIVET_FORCE_CHUNKED=1` runs the chunk engine on a one-GPU host.
- [ ] AMF: no `reset` yet (default → rebuild per chunk). AMF's
      `AMF_VIDEO_ENCODER_FORCE_PICTURE_TYPE`/`Drain` + `ReInit` is the
      candidate; needs RDNA hardware to verify.
- [ ] Not urgent: the single-file pipeline is **decode-bound** long before
      session setup matters. Measured 109 fps for 1080p H.264 -> HEVC with all
      three Arcs available, one decode pump feeding them; the helpers spend
      most of their time waiting on frames, not on session init. Fix the
      decode side first if throughput is the goal.

---

## Encode tuning — H.264 / H.265 calibration

`tuning::qsv_params` now branches per codec: AV1 keeps its 0..255 q-index and
H.264/HEVC get an ordinary 0..51 QP, which is what stopped an HEVC job being
handed `libaom_cq * 4` (up to 152) as its QPI.

The two branches don't have equal provenance, and shouldn't be read as if they
do. The **AV1** anchors are measured against libaom as the cross-encoder
reference (`docs/av1-tuning-research.md`, which the tuning code cites but
which is not in the tree). The
**H.264 / HEVC** anchors are the conventional x264 / x265 CRF values per tier
(18 / 22 / 26 / 32) — a sound starting point, but convention, not measurement.

- [ ] Run the same offline VMAF sweep for QSV HEVC and H.264 that §2.6 defines
      for AV1, and replace the anchors in `qsv_h26x_params` with the measured
      values. Until then a given `QualityTarget` is *not* guaranteed to land in
      the same VMAF band across codecs the way it does across AV1 backends.
- [ ] Same gap on the NVENC side: `nvenc_av1_params` is the only NVENC table,
      so H.264/H.265 on NVENC inherit AV1 calibration too.

---

## Audio — multichannel decode

The **encode** side of surround is done and wired: `channelmap`
([docs/audio-filters.md](docs/audio-filters.md)) remaps channels on decoded PCM,
and the Opus encoder carries 1–8 channels (family 0 for mono/stereo, family 1
multistream for 3–8, RFC 7845 §5.1.1.2). The job layer no longer drops >2ch.

The **decode** side covers **AAC, MP3, MP2, Vorbis, Opus, AC-3, E-AC-3 and the
DTS core** (the last with a real-world caveat, below). So 5.1 AAC / Vorbis /
Opus / AC-3 / E-AC-3 → Opus 5.1, or a downmix of any of them
(`--audio-channels`, ITU-R BS.775), work today. HE-AAC and HE-AAC v2 decode in
full since 2026-10-03 (decisions.md §26).

- [x] **Output channel layouts** (`--audio-channels source|mono|stereo|5.1|7.1`,
      2026-09-27): BS.775 downmix, LFE dropped, normalised; no upmix. Decoders
      report their layout (AC-3 `acmod`, DTS `AMODE`). HLS stereo fallback
      rendition (`--audio-stereo-fallback`).
- [x] **Opus decoder** (2026-09-27; libopus at first, rivet-opus since
      2026-10-03), so Opus sources can be downmixed and re-encoded.
- [x] **Audio-only MP4 (`.m4a`)** for `mode=audio` with Opus / AAC
      (2026-09-27): with `audio-container=mp4` they are written to an `.m4a`,
      as FLAC and ALAC are; only the bare `.mp3` still refuses them, and says
      so.
- [x] **Clean-room MP3 encoder** (2026-10-03): rivet-mp3 (`crates/mp3`)
      replaced the runtime-loaded LAME and the `lame` feature, and minimp3
      for decode (decisions.md §21).
- [x] **Every audio codec our own, and an output** (2026-10-03): rivet-opus
      replaced libopus, rivet-vorbis lewton; Vorbis, AC-3, E-AC-3, DTS,
      HE-AAC and HE-AAC v2 are outputs; Ogg files are read and written
      (decisions.md §37).
- [ ] **E-AC-3 7.1 output**: the encoder writes it as a dependent substream,
      but the `dec3` writer (one independent substream, `num_dep_sub` 0), the
      MP4 muxer's six-channel gate for E-AC-3 and the decoder (substream 0
      only) all stop at 5.1, so `audio=eac3` downmixes 7.1 today.

- [x] **In-tree DTS Coherent Acoustics core decoder**
      (landed 2026-09-13 in `codec/src/audio/decode/dts/`; since 2026-10-02 the
      `rivet-dts` crate,
      [safewords/rivet-dts](https://github.com/safewords/rivet-dts),
      the `crates/dts` submodule, with `codec/src/audio/decode/dts.rs` its adapter). 5.1 / stereo / mono,
      every core sample rate, ≤ 24-bit, from MKV `A_DTS` and MP4
      `dtsc`/`dtsh`/`dtsl` or ffmpeg's `mp4a` + esds OTI 0xA9 form (the DTS-HD
      extension substream is skipped, the lossy core decodes). Every normative table is transcribed by
      `crates/dts/tools/dts_gen_tables.py` from the free ETSI TS 102 114 V1.6.1 PDF,
      cross-checked against V1.2.1, with Kraft/prefix checks on all 62 Huffman
      books. Matches libavcodec to ~1e-6 relative RMS on ffmpeg-made vectors
      (`crates/dts/tests/dts_core.rs`); job e2e in `rivet/tests/dts_audio.rs`.

      **Caveat — the two D.10 VQ code books are not published anywhere lawful**
      (every ETSI edition says "Due to its extensive size, this table is not
      included here"; the DTS patents describe them without listing them; the
      only copies are in libavcodec/libdcadec, excluded by the licence rule).
      Without D.10.1 an ADPCM-predicted subband cannot be reconstructed, so
      such frames are **refused by name** and the job drops the track with the
      reason. Measured on a commercial DTS-HD MA core (60 s): 91 % of frames
      predict at least one subband, so disc-sourced DTS mostly refuses;
      ffmpeg-encoded DTS never predicts and decodes completely. D.10.2 (HF VQ,
      subbands 28–31 on that track) decodes as silence, which the spec permits.
      Decision needed to close the gap: (a) obtain the D.10 code books under
      licence from DTS/Xperi (they are the encoder vendor's trained tables);
      (b) keep passthrough for such tracks; (c) a platform decoder.
      Not exercised by any available encoder: the perfect-reconstruction
      prototype (`FILTS` = 1), Huffman-coded `ABITS`/`SCALES` differences,
      transients (`TMODE`), joint intensity coding, sum/difference coding —
      all transcribed from the spec text and unit-tested, none conformance-tested.

- [x] **In-tree AC-3 / E-AC-3 decoder** (`codec/src/audio/decode/ac3/`, 2026-08-27;
      verified and landed 2026-09-13; since 2026-10-02 the `rivet-ac3` crate,
      [safewords/rivet-ac3](https://github.com/safewords/rivet-ac3),
      the `crates/ac3` submodule, with `codec/src/audio/decode/ac3.rs` its adapter). Written from ATSC A/52:2018; every
      normative table transcribed from the spec and pinned by per-table tests
      (`tables.rs`), never taken from another implementation. AC-3 complete
      (block switching, dither, coupling with phase flags, rematrixing, delta
      bit allocation, `dynrng` on by default and scalable through
      `Ac3Options::drc_scale`). E-AC-3 independent substream 0: all frame
      sizes, reduced sample rates, frame exponent strategies, the SNR offset
      strategies, standard coupling, spectral extension, AHT (VQ + GAQ).
      Cross-checked against libavcodec on 30 ffmpeg-made vectors (the
      dither-stripped copies agree to ≤ 0.03 LSB16 RMS / 0.32 peak, i.e. float
      rounding; the dithered ones sit at the measured noise floor) and on
      Dolby-encoded FATE streams (AC-3 5.1 / 2.0 / 3/1, E-AC-3 stereo and 5.1
      incl. 1-block frames, spectral extension and AHT); `rivet transcode` takes
      5.1 AC-3 / E-AC-3 in MP4, MKV and TS to Opus 5.1. Numbers, the two places
      libavcodec deviates from A/52 (its single-channel block-switch overlap and
      its LFE noise fill on AHT bins) and the gate's rationale:
      [docs/codec-decode.md](docs/codec-decode.md#ac-3--e-ac-3-decoder).

      Still open, refused or skipped **by name**:
      - [ ] E-AC-3 **enhanced coupling** (`ecplinu = 1`) → `Unsupported`. No encoder
            on this box produces it (libavcodec refuses it too), so there is no
            cross-check vector; implement from Annex E §3.5 when one exists.
      - [ ] E-AC-3 **dependent substreams / channel extensions** (7.1 and above):
            skipped per Annex E §3.8.1, so a 7.1 stream decodes as its 5.1 core.
            Needs the `chanmap` merge and a second decoder instance per substream
            (FATE's `the_great_wall_7.1.eac3` is the vector).
      - [ ] `dialnorm` / `compr` (heavy compression) are parsed, not applied — the
            libavcodec default; a `--audio-filter volume` covers the loudness case.
      - [ ] E-AC-3 **spectral extension** streams (Dolby's `csi_miami_*_spx`, which
            also carry AHT) sit at 1.2–1.8× the dither-only expectation against
            libavcodec on the fbw channels: level-proportional and uncorrelated
            with AHT use (AHT channel-frames 2.2 % of level, non-AHT 1.5 %), so
            it is the SPX noise blend's random sequence — Annex E §3.6.4.2 fixes
            no distribution — not the VQ / GAQ arithmetic. There is no
            deterministic SPX vector (the noise cannot be switched off in the
            stream), so the sweep gates those streams at 2.5× / 3.5× and says
            so; a spec-literal SPX vector would need a Dolby encoder that
            transmits `spxblnd = 31` (all signal, no noise).

- [x] **AAC-LC decoder** (2026-09-28), in the `rivet-aac` crate
      ([safewords/rivet-aac](https://github.com/safewords/rivet-aac),
      the `crates/aac` submodule), which the AAC-LC encoder moved into as well.
      ADTS and raw access units with the AudioSpecificConfig; channel
      configurations 1–7 and program_config_element layouts; long / start /
      short / stop windows (sine and KBD), M/S, intensity stereo, PNS, TNS and
      pulse data. Agrees with ffmpeg's decoder, as a black box, to float
      rounding on ffmpeg's and fdk-aac's streams from 8 to 96 kHz. AAC sources
      can now be downmixed, filtered and transcoded to Opus, MP3, FLAC and
      ALAC, and are still passed through when nothing asks for a change.
      HE-AAC / HE-AAC v2 decoded first as their AAC-LC core; since
      2026-10-03 in full (SBR, PS: the owner's request of 2026-10-02), with
      `he-aac=auto|passthrough|core` deciding whether an HE-AAC source is
      decoded in full, not at all, or as its core. USAC is not implemented. The owner's exception for the encoder's tables
      (the re-hosted ISO/IEC 13818-7:2004, approved 2026-09-28) covers the
      decoder's too; provenance in docs/decisions.md §26.
      Not done: AAC Main / SSR / LTP and coupling channel elements (refused
      by name; AAC-LC encoders do not produce them).

---

## Subtitles — ✅ done

Text subtitle passthrough (`-c:s copy`): every text track (Matroska SRT / ASS /
WebVTT; MP4 `tx3g` / `wvtt`) is demuxed and markup-stripped, `--subtitles
all|none|<lang,lang>` selects by language on every surface (CLI, settings
header, batch manifest, HTTP API), single-file MP4 gets a gap-filled `tx3g`
`trak` per language, an HLS package gets a segmented-WebVTT rendition per
language on the video's segment grid (`EXT-X-MEDIA:TYPE=SUBTITLES`,
`X-TIMESTAMP-MAP` per segment), and trims / `splice` re-base each clip's cues
onto the output timeline and merge tracks by language. See
[docs/cli.md#subtitles](docs/cli.md#subtitles).

Deliberately not done:
- **Bitmap subtitles** (PGS / VobSub / DVB) are dropped with a warning and
  will stay dropped — neither `tx3g` nor WebVTT has a bitmap form. Carrying
  them would mean a different output container.
- **Styling** is stripped, not translated: `tx3g` styles by byte range in
  side boxes and WebVTT by inline tags, and a faithful mapping from ASS
  overrides is a project of its own.

---

## Codebase modularization (one-thing-per-file) — ✅ done

Every large source file across all three crates was split into a directory of
small, single-purpose files (a thin `mod.rs` re-exporting the public API +
per-concern submodules + a `tests.rs`), the paradigm set by `codec::filter`.
Pure mechanical splits, no behaviour change — each verified by build + tests
before commit. The 2k–4.6k-line monoliths are gone (largest remaining is a
cohesive parser / encoder core or a test file).

- [x] **codec**: `filter` (per-filter + `denoise/` per-algorithm), `colorspace`,
      `gpu`, `encode/tuning`, `pixel_format` (bitreader/h264/hevc/av1/mpeg2),
      `encode/{nvenc,amf,qsv}`, `decode/nvdec`, `audio/encode/opus`.
- [x] **container**: `mux`, `demux`, `ts`, `cmaf`, `avi`.
- [x] **rivet**: `job`, `multigpu`, `server`, `spec` (policy/rung), `encoder_worker`,
      and `main.rs` (kept as the binary entry; subcommands extracted to `commands/`).
- [x] **second tier** (nested sub-dirs): `pixel_format/av1` (obu/sequence/frame),
      `demux/{mp4,mkv,audio}`, and the two largest files in the tree —
      `mux/tests` + `ts/tests` (split by concern into `tests/` directories).

**No file exceeds ~1300 lines.** The only files still over 1000 are deliberately
left whole — each is a single cohesive function that can't be split by pure code
movement (splitting would mean restructuring the function, i.e. a behaviour-risky
refactor): `encode/nvenc/mod.rs` + `encode/qsv/mod.rs` (the FFI encoder `new()`
/encode), `pixel_format/av1/frame.rs` (the AV1 uncompressed-header parser),
`mux/mod.rs` (the muxer `finalize`). The `nvdec_smoke.rs` integration test is
also left (a test *binary*, awkward to split without changing the binary layout).

Verification: 668 lib+integration tests pass across the three crates; per-file
`#[test]` counts + active assertion counts are byte-for-byte unchanged from before
the work (no test was weakened). One pre-existing failure remains —
`create_decoder_accepts_prores_codec_label` — unrelated to this work (it predates
it; `decode/mod.rs` is unchanged): a stale test expecting a ProRes CPU decoder
that the GPU-only directive removed. (Since 2026-10-02 there is a ProRes CPU
decoder again, `crates/prores`; `crates/codec/tests/prores_dispatch.rs` now pins
that it is listed and builds.)
