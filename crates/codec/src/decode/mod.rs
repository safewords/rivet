//! Decode dispatch: hardware first, then software.
//!
//! [`create_decoder_on`] tries the tiers in this order and takes the first
//! that accepts the stream:
//!
//!   1. NVDEC (NVIDIA, hand-rolled CUVID FFI; `nvidia` feature)
//!   2. AMF   (AMD, hand-rolled AMF FFI; `amd` feature)
//!   3. QSV   (Intel, hand-rolled oneVPL FFI; `qsv` feature)
//!   4. rivet's own pure-Rust decoders, always compiled: `h26x` for H.264 /
//!      HEVC (`RIVET_DISABLE_H26X=1` skips it), and AV1, VP8, VP9, MPEG-1/2,
//!      MPEG-4 Part 2 and ProRes
//!
//! No FFmpeg: libavcodec is not a tier, in any build (see the note in
//! `crates/codec/Cargo.toml`).
//!
//! A hardware tier that cannot start, or that refuses the stream after it
//! was chosen, hands it to the software tiers (see
//! `HardwareThenSoftware`). When no tier takes the codec,
//! [`create_decoder`] fails, naming it.

#[cfg(feature = "amd")]
pub mod amf_dec;
#[cfg(feature = "nvidia")]
pub mod nvdec;
#[cfg(feature = "qsv")]
pub mod qsv_dec;
// Native H.264 / HEVC: this workspace's own decoders (`crates/h26x`), pure
// Rust, always compiled — the only software tier for those two codecs.
pub mod h26x_sw;
// ProRes: this workspace's own decoder (`crates/prores`), pure Rust, always
// compiled — the only decoder in the chain that takes ProRes.
pub mod prores_sw;
// VP8: this workspace's own decoder (`crates/vp8`), pure Rust, always
// compiled — the software tier behind NVDEC.
pub mod vp8_sw;
// VP9: this workspace's own decoder (`crates/vp9`), pure Rust, always
// compiled — the software tier behind NVDEC, AMF and QSV.
pub mod vp9_sw;
// The guard in front of every hardware VP9 decoder: what a vendor's decoder
// is not trusted with (`show_existing_frame`, frame-size changes) goes to
// `vp9_sw` from the last key frame instead.
pub mod vp9_hw_guard;
// MPEG-2 / MPEG-1 video: this workspace's own decoder (`crates/mpeg2`), pure
// Rust, always compiled — the software tier behind NVDEC.
pub mod mpeg2_sw;
// MPEG-4 Part 2 Visual: this workspace's own decoder (`crates/mpeg4`), pure
// Rust, always compiled — the software tier behind NVDEC.
pub mod mpeg4_sw;
// AV1: this workspace's own decoder (`crates/av1`), pure Rust, always
// compiled — the software tier behind NVDEC, AMF and QSV.
pub mod av1_sw;

use crate::frame::{StreamInfo, VideoFrame};
use crate::gpu;

/// Deinterleave an NV12 frame (Y plane + interleaved UV plane, each with its
/// own row stride) into a tightly-packed `Yuv420p` buffer (Y, then U, then V).
/// A shared NV12 deinterleave helper for the GPU decode paths.
#[cfg(any(feature = "nvidia", feature = "amd", feature = "qsv"))]
#[allow(dead_code)]
pub(crate) fn nv12_planes_to_yuv420p(
    y: &[u8],
    y_stride: usize,
    uv: &[u8],
    uv_stride: usize,
    width: usize,
    height: usize,
) -> Vec<u8> {
    // Chroma of an odd-sized 4:2:0 picture is ceil(n / 2), as everywhere
    // else in the pipeline (the P010 path below). This was `width / 2`: a
    // 351-wide 8-bit picture got 175-wide chroma planes, short of what
    // every consumer of the frame reads (QSV VP9 351x287 on an Arc A750:
    // luma exact, chroma wrong).
    let cw = width.div_ceil(2);
    let ch = height.div_ceil(2);
    let mut out = Vec::with_capacity(width * height + 2 * cw * ch);
    for row in 0..height {
        let off = row * y_stride;
        out.extend_from_slice(&y[off..off + width]);
    }
    // U then V, deinterleaved from the UV plane.
    let mut u_plane = Vec::with_capacity(cw * ch);
    let mut v_plane = Vec::with_capacity(cw * ch);
    for row in 0..ch {
        let off = row * uv_stride;
        let r = &uv[off..off + cw * 2];
        for c in 0..cw {
            u_plane.push(r[2 * c]);
            v_plane.push(r[2 * c + 1]);
        }
    }
    out.extend_from_slice(&u_plane);
    out.extend_from_slice(&v_plane);
    out
}

/// Deinterleave host **P010** planes (Y `u16` + interleaved UV `u16`, 10-bit in
/// the HIGH bits) into a packed `Yuv420p10le` buffer (Y, U, V planar, 10-bit in
/// the LOW bits — `>> 6`). Shared by the AMD/Intel GPU decode paths.
#[cfg(any(feature = "amd", feature = "qsv"))]
#[allow(dead_code)]
pub(crate) fn p010_planes_to_yuv420p10le(
    y: &[u8],
    y_stride: usize,
    uv: &[u8],
    uv_stride: usize,
    width: usize,
    height: usize,
) -> Vec<u8> {
    let cw = width.div_ceil(2);
    let ch = height.div_ceil(2);
    let mut out = Vec::with_capacity((width * height + 2 * cw * ch) * 2);
    let rd = |buf: &[u8], off: usize| -> u16 {
        if off + 1 < buf.len() {
            u16::from_le_bytes([buf[off], buf[off + 1]]) >> 6
        } else {
            0
        }
    };
    for row in 0..height {
        let base = row * y_stride;
        for col in 0..width {
            out.extend_from_slice(&rd(y, base + col * 2).to_le_bytes());
        }
    }
    for row in 0..ch {
        let base = row * uv_stride;
        for col in 0..cw {
            out.extend_from_slice(&rd(uv, base + col * 4).to_le_bytes());
        }
    }
    for row in 0..ch {
        let base = row * uv_stride;
        for col in 0..cw {
            out.extend_from_slice(&rd(uv, base + col * 4 + 2).to_le_bytes());
        }
    }
    out
}
use anyhow::{Context, Result, bail};

/// A decoder whose frames arrive already rotated to how they should be seen.
///
/// # Why this wraps rather than being applied by callers
///
/// The rotation lives in the container, and everything downstream — the ladder,
/// the thumbnail, a per-title sample — wants the picture the right way up. Left
/// to callers it is a step each of them has to remember, and the one that
/// forgets produces output that is upside down while the others are fine.
/// Wrapping the decoder means a consumer cannot get this wrong, because it
/// never sees the unrotated frame.
///
/// `Rotation::None` hands frames straight through, so a source with no rotation
/// pays nothing for this existing.
pub struct RotatingDecoder {
    inner: Box<dyn Decoder>,
    degrees: u32,
    info: StreamInfo,
}

impl RotatingDecoder {
    /// Wrap `inner` so every frame is rotated `degrees` clockwise.
    ///
    /// Anything other than 90, 180 or 270 is a pass-through — including 0,
    /// which is the overwhelmingly common case.
    // Returns `inner` itself when there is nothing to rotate, so it cannot
    // return `Self`; renaming it would break every caller.
    #[allow(clippy::new_ret_no_self)]
    pub fn new(inner: Box<dyn Decoder>, degrees: u32) -> Box<dyn Decoder> {
        if !matches!(degrees, 90 | 180 | 270) {
            return inner;
        }

        // 90 and 270 turn the picture on its side, so everything downstream
        // that sizes itself from the stream — the ladder most of all — has to
        // be told the dimensions it will actually receive, not the ones the
        // container recorded.
        let mut info = inner.stream_info().clone();
        if matches!(degrees, 90 | 270) {
            std::mem::swap(&mut info.width, &mut info.height);
        }

        Box::new(Self { inner, degrees, info })
    }
}

impl Decoder for RotatingDecoder {
    fn stream_info(&self) -> &StreamInfo {
        &self.info
    }

    fn push_sample(&mut self, data: &[u8]) -> Result<()> {
        self.inner.push_sample(data)
    }

    fn finish(&mut self) -> Result<()> {
        self.inner.finish()
    }

    fn decode_next(&mut self) -> Result<Option<VideoFrame>> {
        let Some(frame) = self.inner.decode_next()? else { return Ok(None) };
        let rotated =
            crate::filter::apply(&frame, &crate::filter::VideoFilter::Rotate(self.degrees))
                .context("rotating a decoded frame")?;
        Ok(Some(rotated))
    }
}

pub trait Decoder: Send {
    fn stream_info(&self) -> &StreamInfo;

    /// Feed one Annex-B (or codec-native — AV1 OBU, VP9 superframe) sample
    /// into the decoder. Implementations may buffer internally until
    /// `finish` is called or may decode eagerly and buffer produced
    /// frames. Pull frames via `decode_next` at any point.
    fn push_sample(&mut self, data: &[u8]) -> Result<()>;

    /// Signal end-of-stream. After this, no more `push_sample` calls;
    /// `decode_next` drains remaining frames.
    fn finish(&mut self) -> Result<()>;

    fn decode_next(&mut self) -> Result<Option<VideoFrame>>;
}

/// Truthy-string parse for env-var opt-outs. `1` / `true` / `yes` / `on`
/// / `y` / `t` (case-insensitive) all resolve true; anything else is
/// false. Mirrors the encode-side helper for symmetry.
#[cfg(feature = "nvidia")]
fn env_flag_truthy(name: &str) -> bool {
    match std::env::var(name) {
        Ok(v) => {
            let v = v.to_ascii_lowercase();
            matches!(v.as_str(), "1" | "true" | "yes" | "on" | "y" | "t")
        }
        Err(_) => false,
    }
}

/// Per-codec NVDEC opt-out check. Mirrors the previous-stack
/// `DISABLE_NVDEC_<CODEC>` granular knob: `DISABLE_NVDEC=1` blocks every
/// codec, `DISABLE_NVDEC_H264=1` blocks just one. Used as a debugging
/// escape hatch when a specific codec/driver combo is misbehaving on
/// the active host (e.g. Blackwell + 4K H.264 silent-stall).
#[cfg(feature = "nvidia")]
fn nvdec_disabled_for(codec_lower: &str) -> bool {
    if env_flag_truthy("DISABLE_NVDEC") {
        return true;
    }
    let codec_canonical = match codec_lower {
        "h264" | "avc1" | "avc" => "H264",
        "h265" | "hevc" | "hvc1" | "hev1" | "hvc2" | "hev2" => "HEVC",
        "vp8" => "VP8",
        "vp9" | "vp09" => "VP9",
        "av1" | "av01" => "AV1",
        "mpeg2" | "mpeg2video" => "MPEG2",
        "mpeg4" | "mp4v" => "MPEG4",
        _ => return false,
    };
    env_flag_truthy(&format!("DISABLE_NVDEC_{codec_canonical}"))
}

/// Whether NVDEC is handed this stream as far as VP8 goes: not when the
/// picture has an odd side. On an RTX 3090 the 16 even-sized RFC 6386
/// comprehensive vectors decode bit-exact and the two odd-sized ones
/// (175x143) come back 174x142; an odd-sized VP8 stream goes to rivet's own
/// decoder. Other codecs pass (VP9's odd sizes are the VP9 guard's).
#[cfg(feature = "nvidia")]
fn nvdec_takes_vp8(codec_lower: &str, info: &StreamInfo) -> bool {
    codec_lower != "vp8" || (info.width % 2 == 0 && info.height % 2 == 0)
}

/// Codecs the NVDEC streaming dispatch supports.
#[cfg(feature = "nvidia")]
fn nvdec_supports(codec_lower: &str) -> bool {
    matches!(
        codec_lower,
        "h264"
            | "avc1"
            | "avc"
            | "h265"
            | "hevc"
            | "hvc1"
            | "hev1"
            | "hvc2"
            | "hev2"
            | "vp8"
            | "vp9"
            | "vp09"
            | "av1"
            | "av01"
            | "mpeg2"
            | "mpeg2video"
            | "mpeg4"
            | "mp4v"
    )
}

/// Decode backends compiled into this build, in dispatch-preference order.
pub fn decode_backends() -> Vec<&'static str> {
    let mut v = Vec::new();
    if cfg!(feature = "nvidia") {
        v.push("nvdec");
    }
    if cfg!(feature = "amd") {
        v.push("amf");
    }
    if cfg!(feature = "qsv") {
        v.push("qsv");
    }
    v.push("h26x");
    v.push("prores");
    v.push("vp8");
    v.push("vp9");
    v.push("mpeg2");
    v.push("mpeg4");
    v.push("av1");
    v
}

/// One codec's decode support across the compiled backends.
#[derive(Debug, Clone, PartialEq, Eq)]
pub struct DecodeSupport {
    /// Canonical codec label, e.g. `"h264"`.
    pub codec: &'static str,
    /// Backend names that can decode it in this build (`"nvdec"`, `"amf"`,
    /// `"qsv"`, `"h26x"`, `"av1"`, ...). Empty = this
    /// build can't decode it.
    pub backends: Vec<&'static str>,
}

/// Which compiled backends decode each common codec, for `rivet capabilities`.
pub fn decode_capabilities() -> Vec<DecodeSupport> {
    const CODECS: &[&str] = &[
        "h264", "hevc", "vp8", "vp9", "av1", "mpeg2", "mpeg4", "h263", "prores",
    ];
    CODECS
        .iter()
        .map(|&codec| {
            let mut backends: Vec<&'static str> = Vec::new();
            #[cfg(feature = "nvidia")]
            if nvdec_supports(codec) {
                backends.push("nvdec");
            }
            // AMF: what this host's AMD GPU actually has a decoder component
            // for (`CreateComponent` per codec, probed once), not just what
            // the build binds — a VCN without an AV1 block must not be
            // reported as decoding AV1.
            #[cfg(feature = "amd")]
            if amf_dec::host_supports(codec) && amf_takes(codec) {
                backends.push("amf");
            }
            // QSV: ask the driver what this host's silicon can actually decode
            // (MFXVideoDECODE_Query), not just what the build handles — so the
            // report reflects the real adapter (e.g. an older iGPU without AV1
            // decode). Probed once + cached; empty on a non-Intel host.
            #[cfg(feature = "qsv")]
            if qsv_dec::probe_decode_caps().contains(&codec) {
                backends.push("qsv");
            }
            // The software tiers, in the order they are tried. Listed at all
            // because a report that omitted them would understate what this
            // build can do on a host with no decode silicon — and listed only
            // for codecs each one actually serves, because the opposite
            // mistake is what got the previous FFmpeg integration deleted:
            // eight codecs advertised through a decoder `create_decoder` never
            // constructed.
            if h26x_sw::supports(codec) && !h26x_disabled() {
                backends.push("h26x");
            }
            if prores_sw::supports(codec) {
                backends.push("prores");
            }
            if vp8_sw::supports(codec) {
                backends.push("vp8");
            }
            if vp9_sw::supports(codec) {
                backends.push("vp9");
            }
            if mpeg2_sw::supports(codec) {
                backends.push("mpeg2");
            }
            if mpeg4_sw::supports(codec) {
                backends.push("mpeg4");
            }
            if av1_sw::supports(codec) {
                backends.push("av1");
            }
            DecodeSupport { codec, backends }
        })
        .collect()
}

/// Construct a decoder for `codec`, on the first adapter of each vendor.
/// Hardware first — NVDEC, then AMF, then QSV; NVIDIA wins when several
/// vendors are present (NVDEC is generally lower-latency on the standard
/// codec set and is what the production fleet has been tuned against) —
/// then the software tiers: rivet's own decoders (see the module docs). Fails only when no compiled tier
/// takes the codec.
/// The threads one of the workspace's own threaded software decoders (VP8,
/// VP9, MPEG-2, ProRes) decodes on: `env` when it holds a positive count,
/// else the [thread budget](crate::filter::with_thread_budget) of the decode
/// pump building it (several range pumps share the machine), else the
/// runtime's available parallelism, which respects a container CPU quota. A
/// lone pump decodes the source once for the whole ladder, so one decoder
/// owning the cores is the intended shape (as `h26x_sw`); the output does
/// not depend on the count.
pub(crate) fn sw_decode_threads(env: &str) -> usize {
    std::env::var(env)
        .ok()
        .and_then(|v| v.trim().parse::<usize>().ok())
        .filter(|&n| n > 0)
        .or_else(|| Some(crate::filter::thread_budget()).filter(|&n| n > 0))
        .unwrap_or_else(|| std::thread::available_parallelism().map_or(1, |n| n.get()))
}

pub fn create_decoder(codec: &str, info: StreamInfo) -> Result<Box<dyn Decoder>> {
    create_decoder_on(codec, info, None)
}

/// Construct a decoder pinned to a specific `gpu_index` when one is
/// supplied. `None` preserves the legacy "pick the first matching
/// adapter" behaviour for one-shot callers (thumbnails, tests, benches)
/// that don't care about distributing work across physical GPUs.
///
/// The pipeline's per-rung decode pumps should ALWAYS pass `Some(idx)`
/// so each rung's decode session lands on a distinct adapter — without
/// this, every QSV session piles onto the first physical Intel card
/// regardless of what the GPU pool's lease said. See the project memo
/// on QSV multi-adapter session pinning.
pub fn create_decoder_on(
    codec: &str,
    info: StreamInfo,
    // Only the hardware tiers read the pin; a build with none of them has
    // nothing to pin it to, and the parameter stays for callers' sake.
    #[cfg_attr(
        not(any(feature = "nvidia", feature = "amd", feature = "qsv")),
        allow(unused_variables)
    )]
    gpu_index: Option<u32>,
) -> Result<Box<dyn Decoder>> {
    let codec_lower = codec.to_ascii_lowercase();
    #[cfg(any(feature = "nvidia", feature = "amd", feature = "qsv"))]
    let gpus = gpu::detect_gpus();

    // Pick the device. If the caller specified gpu_index, honour it
    // (matching against `g.index`). Otherwise fall back to the first
    // of each vendor — the legacy behaviour for callers that don't
    // care about pinning.
    #[cfg(feature = "nvidia")]
    let nvidia = match gpu_index {
        Some(idx) => gpus
            .iter()
            .find(|g| matches!(g.vendor, gpu::GpuVendor::Nvidia) && g.index == idx),
        None => gpus
            .iter()
            .find(|g| matches!(g.vendor, gpu::GpuVendor::Nvidia)),
    };

    // NVIDIA / NVDEC first — our hand-rolled CUVID FFI (`nvidia` feature). One
    // portable decoder for everything NVDEC handles: H.264/HEVC/AV1/VP8/VP9,
    // MPEG-2/MPEG-4 Part 2, and 10-bit P016.
    #[cfg(feature = "nvidia")]
    if let Some(dev) = nvidia
        && nvdec_supports(&codec_lower)
        && !nvdec_disabled_for(&codec_lower)
        && nvdec_takes_vp8(&codec_lower, &info)
    {
        tracing::info!(
            backend = "nvdec",
            codec = %codec_lower,
            gpu_index = dev.index,
            gpu_name = %dev.name,
            "NVDEC decoder engaged (hand-rolled CUVID FFI)"
        );
        // A tier that cannot start is a tier that declines, not a job that
        // fails. See the QSV arm below, which is where this cost a real
        // upload.
        let vendor_index = dev.vendor_index;
        let decoder = vp9_guarded(
            "NVDEC",
            nvdec::NvdecDecoder::new(info.clone(), vendor_index),
            &codec_lower,
            &info,
            vp9_hw_guard::NVDEC_POLICY,
            Box::new(move |i| Ok(nvdec::NvdecDecoder::new(i.clone(), vendor_index))),
        );
        return Ok(guarded(decoder, &codec_lower, info));
    }

    // AMD / AMF hardware decode — hand-rolled AMF FFI (`amd` feature).
    #[cfg(feature = "amd")]
    {
        let amd = match gpu_index {
            Some(idx) => gpus
                .iter()
                .find(|g| matches!(g.vendor, gpu::GpuVendor::Amd) && g.index == idx),
            None => gpus
                .iter()
                .find(|g| matches!(g.vendor, gpu::GpuVendor::Amd)),
        };
        if let Some(dev) = amd
            && amf_dec::host_supports(&codec_lower)
            && amf_takes(&codec_lower)
        {
            tracing::info!(
                backend = "amf",
                codec = %codec_lower,
                gpu_index = dev.index,
                gpu_name = %dev.name,
                "AMF decoder engaged (hand-rolled AMF FFI)"
            );
            match amf_dec::AmfDecoder::new(info.clone(), dev.vendor_index) {
                Ok(decoder) => {
                    let vendor_index = dev.vendor_index;
                    let decoder = vp9_guarded(
                        "AMF",
                        Box::new(decoder),
                        &codec_lower,
                        &info,
                        vp9_hw_guard::AMF_POLICY,
                        Box::new(move |i| Ok(Box::new(amf_dec::AmfDecoder::new(i.clone(), vendor_index)?) as Box<dyn Decoder>)),
                    );
                    return Ok(guarded(decoder, &codec_lower, info));
                }
                Err(e) => tracing::warn!(
                    error = %e,
                    codec = %codec_lower,
                    gpu_index = dev.index,
                    "AMF decode could not start; trying the next tier"
                ),
            }
        }
    }

    // Intel / QSV hardware decode — hand-rolled oneVPL FFI (`qsv` feature).
    #[cfg(feature = "qsv")]
    {
        let intel = match gpu_index {
            Some(idx) => gpus
                .iter()
                .find(|g| matches!(g.vendor, gpu::GpuVendor::Intel) && g.index == idx),
            None => gpus
                .iter()
                .find(|g| matches!(g.vendor, gpu::GpuVendor::Intel)),
        };
        if let Some(dev) = intel
            && qsv_dec::supports(&codec_lower)
        {
            tracing::info!(
                backend = "qsv",
                codec = %codec_lower,
                gpu_index = dev.index,
                gpu_name = %dev.name,
                "QSV decoder engaged (hand-rolled oneVPL FFI)"
            );
            // Declining, not failing.
            //
            // `MFXVideoDECODE_Init failed: -3` is MFX_ERR_UNSUPPORTED: the card
            // is there and oneVPL loaded, and it will not decode *this* stream
            // — a profile or a resolution outside what the fixed-function block
            // handles. Propagating that killed the job outright on a host with
            // a perfectly good software decoder compiled in and every other
            // tier untried. A real 1920x818 H.264 upload died this way while a
            // 640x360 clip through the same worker succeeded.
            match qsv_dec::QsvDecoder::new(info.clone(), dev.vendor_index) {
                Ok(decoder) => {
                    let vendor_index = dev.vendor_index;
                    let decoder = vp9_guarded(
                        "QSV",
                        Box::new(decoder),
                        &codec_lower,
                        &info,
                        vp9_hw_guard::QSV_POLICY,
                        Box::new(move |i| Ok(Box::new(qsv_dec::QsvDecoder::new(i.clone(), vendor_index)?) as Box<dyn Decoder>)),
                    );
                    return Ok(guarded(decoder, &codec_lower, info));
                }
                Err(e) => tracing::warn!(
                    error = %e,
                    codec = %codec_lower,
                    gpu_index = dev.index,
                    "QSV decode could not start; trying the next tier"
                ),
            }
        }
    }

    create_software_decoder(&codec_lower, info)
}

/// The tiers that need no hardware.
///
/// Split out of [`create_decoder_on`] so a hardware decoder that fails *after*
/// being chosen can still reach them — see [`HardwareThenSoftware`]. Inline,
/// they were reachable only by falling off the end of the tier list, which a
/// decoder that has already been returned can never do.
fn create_software_decoder(codec_lower: &str, info: StreamInfo) -> Result<Box<dyn Decoder>> {
    // ProRes: no hardware tier takes it, and nothing below decodes it.
    if prores_sw::supports(codec_lower) {
        let mut prores_info = info;
        prores_info.codec = codec_lower.to_string();
        let dec = prores_sw::ProresDecoder::new(prores_info)?;
        tracing::info!(backend = "prores", "ProRes software decode engaged (rivet's own decoder)");
        return Ok(Box::new(dec));
    }
    // VP8: behind NVDEC, the only software decoder for it.
    if vp8_sw::supports(codec_lower) {
        let mut vp8_info = info;
        vp8_info.codec = codec_lower.to_string();
        let dec = vp8_sw::Vp8Decoder::new(vp8_info)?;
        tracing::info!(backend = "vp8", "VP8 software decode engaged (rivet's own decoder)");
        return Ok(Box::new(dec));
    }
    // VP9: behind the hardware tiers, the only software decoder for it.
    if vp9_sw::supports(codec_lower) {
        let mut vp9_info = info;
        vp9_info.codec = codec_lower.to_string();
        let dec = vp9_sw::Vp9Decoder::new(vp9_info)?;
        tracing::info!(backend = "vp9", "VP9 software decode engaged (rivet's own decoder)");
        return Ok(Box::new(dec));
    }
    // MPEG-2 / MPEG-1 video: behind NVDEC, the only software decoder for it.
    if mpeg2_sw::supports(codec_lower) {
        let mut mpeg2_info = info;
        mpeg2_info.codec = codec_lower.to_string();
        let dec = mpeg2_sw::Mpeg2Decoder::new(mpeg2_info)?;
        tracing::info!(backend = "mpeg2", "MPEG-2 software decode engaged (rivet's own decoder)");
        return Ok(Box::new(dec));
    }
    // MPEG-4 Part 2: behind NVDEC, the only software decoder for it.
    if mpeg4_sw::supports(codec_lower) {
        let mut mpeg4_info = info;
        mpeg4_info.codec = codec_lower.to_string();
        let dec = mpeg4_sw::Mpeg4Decoder::new(mpeg4_info)?;
        tracing::info!(backend = "mpeg4", "MPEG-4 Part 2 software decode engaged (rivet's own decoder)");
        return Ok(Box::new(dec));
    }
    // AV1: behind NVDEC, AMF and QSV, the only software decoder for it. It
    // logs its own engagement, with its throughput.
    if av1_sw::supports(codec_lower) {
        let mut av1_info = info;
        av1_info.codec = codec_lower.to_string();
        return Ok(Box::new(av1_sw::Av1Decoder::new(av1_info)?));
    }

    // The native H.264 / HEVC decoders: the only software tier for them.
    //
    // Pure Rust, always compiled, bit-exact against the conformance suites,
    // threaded across the machine — see `h26x_sw`. What it refuses (data
    // partitioning, unequal luma / chroma depths, depths the pipeline has no
    // pixel format for) fails the decode; it is said up front on the
    // parameter set, so the job fails before any work is done.
    //
    // `RIVET_DISABLE_H26X=1` skips it, which leaves H.264 / HEVC to the
    // hardware tiers alone.
    if h26x_sw::supports(codec_lower) && !h26x_disabled() {
        let mut native_info = info;
        native_info.codec = codec_lower.to_string();
        let dec = h26x_sw::H26xDecoder::new(native_info)?;
        tracing::info!(
            backend = "h26x",
            codec = %codec_lower,
            "native software decode engaged (rivet's own H.264/HEVC decoders)"
        );
        return Ok(Box::new(dec));
    }
    bail!(
        "no decoder available for codec '{}' on this host \n         (NVIDIA GPUs cover h264/h265/vp8/vp9/av1/mpeg2/mpeg4; \n          Intel Arc/Meteor Lake+ covers h264/h265/vp9/av1; \n          the native software tiers cover H.264 and HEVC to 12-bit 4:2:0/4:2:2/4:4:4, AV1, ProRes, VP8, VP9, MPEG-1/2 and MPEG-4 Part 2).",
        codec_lower
    )
}

/// `RIVET_DISABLE_H26X=1` takes the native tier out of the chain.
fn h26x_disabled() -> bool {
    matches!(
        std::env::var("RIVET_DISABLE_H26X").as_deref().map(str::to_ascii_lowercase).as_deref(),
        Ok("1" | "true" | "yes" | "on" | "y" | "t")
    )
}

/// Whether the AMF tier is offered `codec_lower`: every codec it has a
/// decoder for, except VP9 unless `RIVET_AMF_VP9=1`.
///
/// VP9 is off by default on AMF. On the one AMD GPU this was run on (a Ryzen
/// 9 9950X iGPU), the WebM project's VP9 vectors drove the video engine into
/// timeouts (LiveKernelEvent 141 / a2000002) — first through two decoder
/// bugs since fixed (`AMF_REPEAT` answered by resubmitting the buffer, frames
/// larger than the decoder was set up for), then on an eight-frame
/// superframe the VP9 guard now keeps from it, and then once more on a run
/// in which the decoder was handed a single ordinary key frame before the
/// guard switched, so nothing the guard reads explains it. Hundreds of
/// streams decoded bit-exact in between, but a decoder that can hang the
/// GPU on input that cannot be screened for is not one to pick unasked.
/// `RIVET_AMF_VP9=1` opts back in, behind the guard at its strictest
/// ([`vp9_hw_guard::AMF_POLICY`]).
#[cfg(feature = "amd")]
fn amf_takes(codec_lower: &str) -> bool {
    !vp9_sw::supports(codec_lower)
        || matches!(
            std::env::var("RIVET_AMF_VP9").as_deref().map(str::to_ascii_lowercase).as_deref(),
            Ok("1" | "true" | "yes" | "on")
        )
}

/// Put the VP9 guard in front of a hardware decoder of a VP9 stream; any
/// other codec passes through.
#[cfg(any(feature = "nvidia", feature = "amd", feature = "qsv"))]
fn vp9_guarded(
    label: &'static str,
    decoder: Box<dyn Decoder>,
    codec_lower: &str,
    info: &StreamInfo,
    policy: vp9_hw_guard::Vp9HwPolicy,
    rebuild: vp9_hw_guard::Rebuild,
) -> Box<dyn Decoder> {
    if vp9_sw::supports(codec_lower) {
        Box::new(vp9_hw_guard::Vp9HardwareGuard::new(label, decoder, info.clone(), policy).with_rebuild(rebuild))
    } else {
        decoder
    }
}

/// Wrap a hardware decoder so a refusal degrades instead of failing.
///
/// A hardware decoder can accept construction and then refuse the stream,
/// by which point every other tier has been passed over. A real 1920x818
/// upload failed exactly there, on a host whose software decoder was
/// compiled in, enabled, and never reached. NVDEC refuses late: its parser
/// reads a sample's last NAL unit when the next sample arrives, so an
/// unsupported sequence (10-bit H.264 on a card whose NVDEC has none) is
/// refused on the second push — and a stream `cuvidCreateDecoder` will not
/// take is refused only once the callbacks' failure is surfaced.
///
/// This keeps the fallback available until the hardware has decoded a frame:
/// a refusal before that — from a push, from `finish`, from `decode_next`, or
/// a stream the hardware took to the end without yielding a frame — rebuilds
/// the next tier and replays everything fed so far, so the job continues
/// instead of ending. After the first frame the hardware has proved itself
/// and the fallback is dropped — a decoder that fails on sample nine thousand
/// is a real failure, not a capability question, and pretending otherwise
/// would silently re-decode a whole video.
#[cfg(any(feature = "nvidia", feature = "amd", feature = "qsv"))]
fn guarded(primary: Box<dyn Decoder>, codec_lower: &str, info: StreamInfo) -> Box<dyn Decoder> {
    let codec = codec_lower.to_string();
    Box::new(HardwareThenSoftware::new("hardware", primary, Box::new(move || create_software_decoder(&codec, info))))
}

/// Builds the next decoder tier down, once.
#[cfg(any(test, feature = "nvidia", feature = "amd", feature = "qsv"))]
type FallbackBuilder = Box<dyn FnOnce() -> Result<Box<dyn Decoder>> + Send>;

/// The most bytes held for a replay. A primary that has decoded nothing by
/// then keeps its samples to itself: a fallback past that point would mean
/// holding the whole file, and the refusals the guard exists for come in the
/// first few samples.
#[cfg(any(test, feature = "nvidia", feature = "amd", feature = "qsv"))]
const REPLAY_LIMIT: usize = 64 << 20;

#[cfg(any(test, feature = "nvidia", feature = "amd", feature = "qsv"))]
struct HardwareThenSoftware {
    /// What the primary is, for the log and the error (`hardware`).
    label: &'static str,
    primary: Box<dyn Decoder>,
    /// Rebuilds the next tier down. `None` once the primary has decoded a
    /// frame, once the replay outgrew [`REPLAY_LIMIT`], or once it has been
    /// used.
    fallback: Option<FallbackBuilder>,
    /// Everything pushed before the primary proved itself, to replay.
    replay: Vec<Vec<u8>>,
    replay_bytes: usize,
    /// `finish` was called: a replacement built after it is finished too.
    finished: bool,
}

#[cfg(any(test, feature = "nvidia", feature = "amd", feature = "qsv"))]
impl HardwareThenSoftware {
    fn new(label: &'static str, primary: Box<dyn Decoder>, fallback: FallbackBuilder) -> Self {
        Self { label, primary, fallback: Some(fallback), replay: Vec::new(), replay_bytes: 0, finished: false }
    }

    /// Swap in the fallback and replay what the primary was given. Without a
    /// fallback the primary's error stands; with one that cannot be built,
    /// the error names both.
    fn degrade(&mut self, why: &anyhow::Error) -> Result<()> {
        let Some(build) = self.fallback.take() else {
            bail!("{why:#}");
        };

        let label = self.label;
        let mut replacement = build().with_context(|| {
            format!("the {label} decoder refused this stream ({why:#}), and no software decoder can take it")
        })?;
        tracing::warn!(
            decoder = label,
            error = %format!("{why:#}"),
            replayed_samples = self.replay.len(),
            "the {label} decoder refused this stream; falling back to software"
        );
        for sample in std::mem::take(&mut self.replay) {
            replacement.push_sample(&sample)?;
        }
        self.replay_bytes = 0;
        if self.finished {
            replacement.finish()?;
        }

        self.primary = replacement;
        Ok(())
    }

    /// The primary decoded a frame: it is the decoder now.
    fn proved(&mut self) {
        self.fallback = None;
        self.replay = Vec::new();
        self.replay_bytes = 0;
    }
}

#[cfg(any(test, feature = "nvidia", feature = "amd", feature = "qsv"))]
impl Decoder for HardwareThenSoftware {
    fn stream_info(&self) -> &StreamInfo {
        self.primary.stream_info()
    }

    fn push_sample(&mut self, data: &[u8]) -> Result<()> {
        // An empty sample carries nothing to replay (the decoders skip it).
        if self.fallback.is_some() && !data.is_empty() {
            if self.replay_bytes + data.len() > REPLAY_LIMIT {
                tracing::debug!(
                    held = self.replay_bytes,
                    "no frame yet from the hardware decoder; too much to replay, keeping it without a fallback"
                );
                self.proved();
            } else {
                self.replay.push(data.to_vec());
                self.replay_bytes += data.len();
            }
        }

        match self.primary.push_sample(data) {
            Ok(()) => Ok(()),
            Err(e) => self.degrade(&e),
        }
    }

    fn finish(&mut self) -> Result<()> {
        self.finished = true;
        match self.primary.finish() {
            Ok(()) => Ok(()),
            Err(e) => self.degrade(&e),
        }
    }

    fn decode_next(&mut self) -> Result<Option<VideoFrame>> {
        match self.primary.decode_next() {
            Ok(Some(frame)) => {
                if self.fallback.is_some() {
                    self.proved();
                }
                Ok(Some(frame))
            }
            // Finished and drained without a single frame: the hardware took
            // the stream and made nothing of it.
            Ok(None) if self.finished && self.fallback.is_some() && !self.replay.is_empty() => {
                let why = anyhow::anyhow!(
                    "it decoded no frame from the {} sample(s) it was given",
                    self.replay.len()
                );
                self.degrade(&why)?;
                self.primary.decode_next()
            }
            Ok(None) => Ok(None),
            Err(e) if self.fallback.is_some() => {
                self.degrade(&e)?;
                self.primary.decode_next()
            }
            Err(e) => Err(e),
        }
    }
}

/// GPU indices whose vendor decoder can handle `codec` in this build (honoring
/// the `DISABLE_NVDEC*` knobs). These are exactly the candidates
/// `create_decoder_on(.., Some(idx))` would dispatch a decoder for — the
/// `--decode-with-fastest` benchmark times each one and pins the pump to the
/// quickest. Order follows `detect_gpus()`.
pub fn decode_capable_gpu_indices(codec: &str) -> Vec<u32> {
    let codec_lower = codec.to_ascii_lowercase();
    gpu::detect_gpus()
        .iter()
        .filter(|g| match g.vendor {
            gpu::GpuVendor::Nvidia => nvidia_can_decode(&codec_lower),
            gpu::GpuVendor::Amd => amd_can_decode(&codec_lower),
            gpu::GpuVendor::Intel => intel_can_decode(&codec_lower),
        })
        .map(|g| g.index)
        .collect()
}

#[cfg(feature = "nvidia")]
fn nvidia_can_decode(c: &str) -> bool {
    nvdec_supports(c) && !nvdec_disabled_for(c)
}
#[cfg(not(feature = "nvidia"))]
fn nvidia_can_decode(_c: &str) -> bool {
    false
}

#[cfg(feature = "amd")]
fn amd_can_decode(c: &str) -> bool {
    amf_dec::host_supports(c) && amf_takes(c)
}
#[cfg(not(feature = "amd"))]
fn amd_can_decode(_c: &str) -> bool {
    false
}

#[cfg(feature = "qsv")]
fn intel_can_decode(c: &str) -> bool {
    qsv_dec::supports(c)
}
#[cfg(not(feature = "qsv"))]
fn intel_can_decode(_c: &str) -> bool {
    false
}

#[cfg(test)]
mod rotating_decoder_tests {
    use super::*;
    use crate::frame::{ColorSpace, PixelFormat};

    /// NVDEC takes an even-sized VP8 stream only; everything else passes.
    #[cfg(feature = "nvidia")]
    #[test]
    fn nvdec_takes_even_sized_vp8_only() {
        let mut info = StreamInfo {
            codec: "vp8".into(),
            width: 176,
            height: 144,
            frame_rate: 30.0,
            duration: 0.0,
            pixel_format: PixelFormat::Yuv420p,
            color_space: ColorSpace::Bt709,
            total_frames: 0,
            bitrate: 0,
            color_metadata: Default::default(),
        };
        assert!(nvdec_takes_vp8("vp8", &info));
        (info.width, info.height) = (175, 143);
        assert!(!nvdec_takes_vp8("vp8", &info));
        assert!(nvdec_takes_vp8("vp9", &info));
        assert!(nvdec_takes_vp8("h264", &info));
    }

    /// An odd-sized NV12 picture: chroma ceil(w / 2) x ceil(h / 2).
    #[cfg(any(feature = "nvidia", feature = "amd", feature = "qsv"))]
    #[test]
    fn nv12_chroma_of_an_odd_picture_is_rounded_up() {
        // 3x3 luma (stride 4), chroma 2x2 interleaved (stride 4).
        let y: Vec<u8> = (0..12).collect();
        let uv: Vec<u8> = vec![100, 200, 101, 201, 102, 202, 103, 203];
        let out = nv12_planes_to_yuv420p(&y, 4, &uv, 4, 3, 3);
        assert_eq!(out.len(), 9 + 2 * 4);
        assert_eq!(&out[..9], &[0, 1, 2, 4, 5, 6, 8, 9, 10]);
        assert_eq!(&out[9..13], &[100, 101, 102, 103]);
        assert_eq!(&out[13..], &[200, 201, 202, 203]);
    }

    /// A decoder that yields one frame with a distinctive top-left pixel.
    struct OneFrame {
        info: StreamInfo,
        yielded: bool,
    }

    impl OneFrame {
        fn boxed(w: u32, h: u32) -> Box<dyn Decoder> {
            let info = StreamInfo {
                codec: "h264".into(),
                width: w,
                height: h,
                frame_rate: 30.0,
                duration: 1.0,
                pixel_format: PixelFormat::Yuv420p,
                color_space: ColorSpace::Bt709,
                total_frames: 1,
                bitrate: 0,
                color_metadata: crate::frame::ColorMetadata::default(),
            };
            Box::new(Self { info, yielded: false })
        }
    }

    impl Decoder for OneFrame {
        fn stream_info(&self) -> &StreamInfo {
            &self.info
        }
        fn push_sample(&mut self, _: &[u8]) -> Result<()> {
            Ok(())
        }
        fn finish(&mut self) -> Result<()> {
            Ok(())
        }
        fn decode_next(&mut self) -> Result<Option<VideoFrame>> {
            if self.yielded {
                return Ok(None);
            }
            self.yielded = true;
            let (w, h) = (self.info.width as usize, self.info.height as usize);
            let mut data = vec![0u8; w * h * 3 / 2];
            data[0] = 200; // top-left luma, the corner we track
            Ok(Some(VideoFrame::new(
                bytes::Bytes::from(data),
                self.info.width,
                self.info.height,
                PixelFormat::Yuv420p,
                ColorSpace::Bt709,
                0,
            )))
        }
    }

    #[test]
    fn a_180_rotation_moves_the_corner_to_the_opposite_corner() {
        // The production case. A marked top-left pixel must end up bottom-right
        // — which is what "upside down" means in pixels rather than in words.
        let (w, h) = (16u32, 8u32);
        let mut d = RotatingDecoder::new(OneFrame::boxed(w, h), 180);
        let frame = d.decode_next().unwrap().expect("a frame");

        assert_eq!((frame.width, frame.height), (w, h), "180 must not resize");
        let last = (w * h - 1) as usize;
        assert_eq!(frame.data[last], 200, "the marked corner did not move");
        assert_eq!(frame.data[0], 0, "the original corner still carries the mark");
    }

    #[test]
    fn ninety_degrees_swaps_the_reported_dimensions() {
        // Everything downstream sizes itself from `stream_info` — the ladder
        // above all. If it keeps reporting the container's dimensions, every
        // rung is computed for a picture the decoder will never hand over.
        let d = RotatingDecoder::new(OneFrame::boxed(1920, 1080), 90);
        assert_eq!((d.stream_info().width, d.stream_info().height), (1080, 1920));
    }

    #[test]
    fn no_rotation_is_the_decoder_itself() {
        // The overwhelmingly common case pays nothing: same dimensions, and no
        // per-frame copy in the path.
        let d = RotatingDecoder::new(OneFrame::boxed(1920, 1080), 0);
        assert_eq!((d.stream_info().width, d.stream_info().height), (1920, 1080));
    }
}

#[cfg(test)]
mod fallback_guard_tests {
    //! The dispatch's hardware → software guard, with the hardware decoder
    //! replaced by a scripted one: the refusals NVDEC makes, made on cue.

    use super::*;
    use crate::frame::{ColorSpace, PixelFormat};
    use std::sync::{Arc, Mutex};

    fn info() -> StreamInfo {
        StreamInfo {
            codec: "h264".into(),
            width: 16,
            height: 16,
            frame_rate: 30.0,
            duration: 1.0,
            pixel_format: PixelFormat::Yuv420p,
            color_space: ColorSpace::Bt709,
            total_frames: 3,
            bitrate: 0,
            color_metadata: crate::frame::ColorMetadata::default(),
        }
    }

    /// A frame whose first byte names the decoder and the sample it came from.
    fn frame(tag: u8) -> VideoFrame {
        let mut data = vec![0u8; 16 * 16 * 3 / 2];
        data[0] = tag;
        VideoFrame::new(bytes::Bytes::from(data), 16, 16, PixelFormat::Yuv420p, ColorSpace::Bt709, 0)
    }

    /// What the scripted hardware decoder does.
    #[derive(Default, Clone, Copy)]
    struct Script {
        /// Refuse the n-th push (0-based), as NVDEC refuses a sequence one
        /// sample late.
        refuse_push: Option<usize>,
        /// Refuse at `finish`.
        refuse_finish: bool,
        /// Refuse from `decode_next`.
        refuse_decode: bool,
        /// Yield a frame per sample (tag 100 + index) as they are pushed.
        yields: bool,
        /// Refuse the n-th push even after yielding frames.
        refuse_after_frames: Option<usize>,
    }

    struct Hardware {
        script: Script,
        pushed: usize,
        ready: std::collections::VecDeque<VideoFrame>,
        info: StreamInfo,
    }

    impl Decoder for Hardware {
        fn stream_info(&self) -> &StreamInfo {
            &self.info
        }
        fn push_sample(&mut self, _: &[u8]) -> Result<()> {
            let n = self.pushed;
            self.pushed += 1;
            if self.script.refuse_push == Some(n) || self.script.refuse_after_frames == Some(n) {
                bail!("NVDEC reject: scripted refusal at sample {n}");
            }
            if self.script.yields {
                self.ready.push_back(frame(100 + n as u8));
            }
            Ok(())
        }
        fn finish(&mut self) -> Result<()> {
            if self.script.refuse_finish {
                bail!("NVDEC could not decode this stream: cuvidCreateDecoder failed: 1");
            }
            Ok(())
        }
        fn decode_next(&mut self) -> Result<Option<VideoFrame>> {
            if self.script.refuse_decode {
                bail!("NVDEC reject: scripted refusal in decode_next");
            }
            Ok(self.ready.pop_front())
        }
    }

    /// The software tier: one frame per sample (tag = the sample's first
    /// byte), and a record of every sample it was given.
    struct Software {
        seen: Arc<Mutex<Vec<Vec<u8>>>>,
        ready: std::collections::VecDeque<VideoFrame>,
        info: StreamInfo,
    }

    impl Decoder for Software {
        fn stream_info(&self) -> &StreamInfo {
            &self.info
        }
        fn push_sample(&mut self, data: &[u8]) -> Result<()> {
            self.seen.lock().unwrap().push(data.to_vec());
            self.ready.push_back(frame(data[0]));
            Ok(())
        }
        fn finish(&mut self) -> Result<()> {
            Ok(())
        }
        fn decode_next(&mut self) -> Result<Option<VideoFrame>> {
            Ok(self.ready.pop_front())
        }
    }

    /// The guard over a scripted hardware decoder; the software tier's
    /// record of samples, or `None` for a build with no software tier.
    fn guard(script: Script, software: bool) -> (HardwareThenSoftware, Arc<Mutex<Vec<Vec<u8>>>>) {
        let seen = Arc::new(Mutex::new(Vec::new()));
        let seen2 = Arc::clone(&seen);
        let hw = Box::new(Hardware { script, pushed: 0, ready: Default::default(), info: info() });
        let fallback: FallbackBuilder = if software {
            Box::new(move || Ok(Box::new(Software { seen: seen2, ready: Default::default(), info: info() }) as Box<dyn Decoder>))
        } else {
            Box::new(|| bail!("no decoder available for codec 'h264' on this host"))
        };
        (HardwareThenSoftware::new("hardware", hw, fallback), seen)
    }

    /// Push samples 1..=n, finish, and collect every frame's tag.
    fn run(g: &mut HardwareThenSoftware, n: u8) -> Result<Vec<u8>> {
        let mut tags = Vec::new();
        for s in 1..=n {
            g.push_sample(&[s])?;
            while let Some(f) = g.decode_next()? {
                tags.push(f.data[0]);
            }
        }
        g.finish()?;
        while let Some(f) = g.decode_next()? {
            tags.push(f.data[0]);
        }
        Ok(tags)
    }

    /// NVDEC's own refusal: the first sample accepted, the sequence refused
    /// when the second arrives. The guard used to count the first accepted
    /// push as proof and drop the fallback, so the job failed; now the
    /// software tier gets every sample from the first and decodes them all.
    #[test]
    fn a_refusal_before_the_first_frame_falls_back_with_every_sample() {
        let (mut g, seen) = guard(Script { refuse_push: Some(1), ..Default::default() }, true);
        assert_eq!(run(&mut g, 3).unwrap(), [1, 2, 3]);
        assert_eq!(*seen.lock().unwrap(), [vec![1u8], vec![2], vec![3]]);
    }

    /// A decoder that takes the whole stream and yields nothing (NVDEC when
    /// `cuvidCreateDecoder` failed and only a callback knew) falls back at
    /// the end, from the first sample.
    #[test]
    fn a_decoder_that_yields_nothing_falls_back_at_the_end() {
        let (mut g, seen) = guard(Script::default(), true);
        assert_eq!(run(&mut g, 3).unwrap(), [1, 2, 3]);
        assert_eq!(seen.lock().unwrap().len(), 3);
    }

    /// Refusals surfaced by `finish` or `decode_next` fall back too.
    #[test]
    fn a_refusal_from_finish_or_decode_next_falls_back() {
        let (mut g, _) = guard(Script { refuse_finish: true, ..Default::default() }, true);
        assert_eq!(run(&mut g, 2).unwrap(), [1, 2]);
        let (mut g, _) = guard(Script { refuse_decode: true, ..Default::default() }, true);
        assert_eq!(run(&mut g, 2).unwrap(), [1, 2]);
    }

    /// Once the hardware has decoded a frame it is the decoder: a later
    /// failure is an error, not a silent re-decode.
    #[test]
    fn a_failure_after_the_first_frame_is_an_error() {
        let (mut g, seen) = guard(Script { yields: true, refuse_after_frames: Some(2), ..Default::default() }, true);
        let err = run(&mut g, 3).expect_err("no fallback after a frame");
        assert!(format!("{err:#}").contains("scripted refusal at sample 2"), "{err:#}");
        assert!(seen.lock().unwrap().is_empty(), "the software tier was never built");
    }

    /// A build with no software tier for the codec fails naming both the
    /// hardware's refusal and the missing software decoder.
    #[test]
    fn with_no_software_tier_the_refusal_is_named() {
        let (mut g, _) = guard(Script { refuse_push: Some(1), ..Default::default() }, false);
        let err = format!("{:#}", run(&mut g, 3).expect_err("nothing to fall back to"));
        assert!(err.contains("the hardware decoder refused this stream (NVDEC reject: scripted refusal at sample 1)"), "{err}");
        assert!(err.contains("no software decoder can take it"), "{err}");
        assert!(err.contains("no decoder available for codec 'h264'"), "{err}");
    }
}
