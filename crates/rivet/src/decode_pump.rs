//! Shared source decode pump.
//!
//! One pump per job (not per rung): demux + decode the source **once**, run
//! the rung-agnostic per-frame work (4:4:4 → 4:2:0 downsample + HDR tonemap),
//! and fan the normalized frame out to N per-rung mpsc channels via cheap
//! `VideoFrame::clone()` (the inner `Bytes` is `Arc`-backed).
//!
//! Per-rung scaling + encoding consume from those channels. Eliminating the
//! redundant per-rung decode is the whole point — a 5-rung ladder decodes the
//! source once, not five times. The cost: the slowest rung backpressures the
//! pump (usually the largest rung, whose encoder is slowest).
//!
//! # Splitting the decode across GPUs
//!
//! One decoder for the whole ladder is one decoder, and on a multi-GPU host
//! every rung then waits on it while the other cards' decode engines sit
//! idle. [`plan_decode_ranges`] cuts the source into ranges that can each be
//! decoded from a keyframe on a segment boundary; the orchestrator runs one
//! pump per range ([`DecodePumpConfig::sample_range`]) on a card, so the
//! cards decode different stretches of the source at the same time and the
//! ladder's segment numbering stays continuous across the join. The ladder
//! cuts the source finer than one range per card and lets each card pull the
//! next range when it is free, so a fast card decodes more of the source than
//! a slow one (`multigpu::ladder`).

use std::time::Instant;

use anyhow::{bail, Context, Result};
use bytes::Bytes;

use codec::frame::{ColorMetadata, ColorSpace, PixelFormat, TransferFn, VideoFrame};
use codec::{colorspace, decode};
use container::streaming;

/// Configuration for one decode pump.
#[derive(Clone)]
pub struct DecodePumpConfig {
    /// Source video codec label (e.g. `"h264"`).
    pub codec_name: String,
    /// Stream info handed to the decoder.
    pub info_for_decoder: codec::frame::StreamInfo,
    /// Source color metadata (drives HDR-aware tonemap vs SDR passthrough).
    pub source_color_metadata: ColorMetadata,
    /// Source pixel format.
    pub source_pixel_format: PixelFormat,
    /// Whether to run the 4:4:4 → 4:2:0 downsample per frame.
    pub needs_downsample: bool,
    /// Which chroma filter that downsample uses (from the spec).
    pub chroma_downsample: codec::colorspace::ChromaDownsample,
    /// The pixel format the encoder was configured for
    /// ([`OutputSpec::resolve_output`](crate::spec::OutputSpec::resolve_output)):
    /// `Yuv420p` or `Yuv420p10le`. Every frame leaving the pump is brought
    /// to it — a 10- or 12-bit SDR source narrowed to 8 for an 8-bit output,
    /// an 8-bit source widened for a 10-bit one — so the encoder never sees
    /// a depth it did not ask for.
    pub output_pixel_format: PixelFormat,
    /// Tonemap policy (from the [`OutputSpec`](crate::spec::OutputSpec)): when
    /// `true`, HDR (PQ/HLG) sources are mapped down to 8-bit SDR BT.709; when
    /// `false`, the source color/transfer/bit-depth passes through unchanged.
    /// The pump does not decide this on its own — the caller sets it from the
    /// spec's [`ColorPolicy`](crate::spec::ColorPolicy).
    pub tonemap_to_sdr: bool,
    /// The HDR transfer (PQ or HLG) an SDR source is mapped into, ITU-R
    /// BT.2408 ([`codec::colorspace::SdrToHdr`]), when the output is HDR and
    /// the source is not — set it from
    /// [`sdr_into_hdr`](crate::spec::sdr_into_hdr). `None` leaves the colour
    /// alone. Without the mapping an HDR policy only re-tagged SDR pixels.
    pub sdr_to_hdr: Option<TransferFn>,
    /// Pin the decoder to this physical GPU; `None` = first matching adapter.
    pub gpu_index: Option<u32>,
    /// Decode only this range of the source, by demuxed sample index:
    /// `[decode_from_sample, end_sample)` is decoded, and of that the frames
    /// from the range's lead-in on are emitted ([`DecodeRange`]). `None`
    /// decodes everything, which is the whole-source pump.
    ///
    /// The range **must** be one [`plan_decode_ranges`] returned — its
    /// `decode_from_sample` carries an IDR/IRAP. Starting anywhere else gives
    /// the decoder a picture whose references it never saw, and the output is
    /// wrong rather than absent.
    ///
    /// Samples before it are still demuxed — they have to be, the demuxer is
    /// a pull API with no seek — but they are not handed to the decoder.
    /// Demuxing is parsing; decoding is the expensive half, and skipping it is
    /// the entire saving. Composes with a clip's trim window, which counts
    /// *decoded* frames: the range decides what is decoded, the trim decides
    /// what is kept.
    pub sample_range: Option<DecodeRange>,
    /// Clockwise rotation the container declared, in degrees (0/90/180/270).
    ///
    /// Applied to every frame as it leaves the decoder, so nothing fed by this
    /// pump has to know the source was recorded on its side or upside down.
    /// See [`codec::decode::RotatingDecoder`]. Set it from
    /// [`DemuxHeader::rotation_degrees`](container::streaming::DemuxHeader) —
    /// and size the rungs from
    /// [`DemuxHeader::upright_dims`](container::streaming::DemuxHeader::upright_dims),
    /// because 90/270 swap the picture's width and height.
    pub rotation_degrees: u32,
    /// Prepared per-frame video filter chain (crop/pad/flip/rotate/grayscale/
    /// overlay/colour/denoise), applied after colorspace normalize and before
    /// the frame is fanned out to the per-rung scalers. Overlay images are
    /// loaded once at prepare time. `Arc` so the per-GPU pump configs clone it
    /// cheaply — the chain is immutable; each pump
    /// [instantiates](codec::filter::FilterChain::instantiate) it per clip, so
    /// a temporal filter's frame history is never shared between streams.
    pub filters: std::sync::Arc<codec::filter::FilterChain>,
    /// Output frames per source frame period when the output frame rate is
    /// capped below the source's ([`decimation`]); `None` keeps every frame.
    /// The pump then drops frames so each output period gets the source
    /// frame showing at its start — the duration is kept and the motion
    /// gets coarser, rather than every frame being kept and the picture
    /// slowed down against its audio.
    pub decimate: Option<f64>,
    /// The job's hooks ([`crate::hooks`]): decoded-frame hooks are handed
    /// frames from this pump before [`FrameNormalizer`], encoder-frame hooks
    /// after it. Empty costs nothing.
    pub hooks: crate::hooks::Hooks,
}

/// The ratio a source at `source_fps` is decimated by when its output is
/// capped at `max_fps`: `Some(max_fps / source_fps)` when the cap is below the
/// source's rate, else `None`. An unknown source rate (0) is not decimated.
pub fn decimation(source_fps: f64, max_fps: Option<f64>) -> Option<f64> {
    let cap = max_fps?;
    (source_fps > 0.0 && cap > 0.0 && cap < source_fps * (1.0 - 1e-6)).then(|| cap / source_fps)
}

/// Output frames that start before source frame period `k` at `ratio`:
/// `ceil(k * ratio)`. A source frame covering periods `[k, k + n)` fills
/// output frames `[out_index(k), out_index(k + n))` — none, one, or (a frame
/// held for several periods) more.
fn out_index(k: u64, ratio: f64) -> u64 {
    (k as f64 * ratio - 1e-9).ceil().max(0.0) as u64
}

/// How many output frames `source_frames` consecutive source frame periods
/// become at `ratio` (see [`DecodePumpConfig::decimate`]).
pub fn output_frames(source_frames: u64, ratio: Option<f64>) -> u64 {
    match ratio {
        Some(r) => out_index(source_frames, r),
        None => source_frames,
    }
}

impl DecodePumpConfig {
    /// The configuration for decoding one source under `spec`: codec, stream
    /// info and source colour from the demuxed `header`; the tonemap, SDR → HDR
    /// mapping and output format from the spec's colour policy
    /// ([`OutputSpec::resolve_output`](crate::spec::OutputSpec::resolve_output));
    /// `filters` (prepared from the spec's chain); decoding on `gpu_index`.
    ///
    /// What the job engine builds for every clip, and what the paths that
    /// decode a source themselves build too (`FrameNormalizer`).
    pub fn for_source(
        header: &streaming::DemuxHeader,
        spec: &crate::spec::OutputSpec,
        filters: std::sync::Arc<codec::filter::FilterChain>,
        gpu_index: Option<u32>,
    ) -> Self {
        let (output_color, output_pixel_format) =
            spec.resolve_output(header.info.color_metadata, header.info.pixel_format);
        Self {
            codec_name: header.codec.clone(),
            info_for_decoder: header.info.clone(),
            source_color_metadata: header.info.color_metadata,
            source_pixel_format: header.info.pixel_format,
            needs_downsample: crate::validate::needs_chroma_downsample(header.info.pixel_format),
            chroma_downsample: spec.chroma_downsample,
            output_pixel_format,
            tonemap_to_sdr: spec.tonemaps(),
            sdr_to_hdr: crate::spec::sdr_into_hdr(
                spec.tonemaps(),
                &header.info.color_metadata,
                &output_color,
            ),
            gpu_index,
            sample_range: None,
            rotation_degrees: header.rotation_degrees,
            filters,
            decimate: decimation(header.info.frame_rate, spec.max_frame_rate),
            hooks: spec.hooks.clone(),
        }
    }
}

/// One contiguous slice of the source, decodable without anything before it.
#[derive(Debug, Clone, Copy, PartialEq, Eq)]
pub struct DecodeRange {
    /// First sample of the range. Always a keyframe.
    pub start_sample: u64,
    /// One past the last sample, or `None` for "to the end of the source".
    pub end_sample: Option<u64>,
    /// Frames before this range — its first segment's index, given a
    /// `frames_per_chunk` that divides the boundary.
    pub start_frame: u64,
    /// Where decoding starts: `start_sample`, or an earlier keyframe when the
    /// range carries a lead-in.
    pub decode_from_sample: u64,
    /// Frames just before `start_frame` this range also emits, ahead of its
    /// own — the previous chunk's tail, which a chunk with a lead-in margin
    /// (single-file chunk-and-stitch) replays to warm its encoder. A range
    /// that emits them starts its first chunk exactly as a whole-source
    /// decode would, so where the source is cut changes nothing in the
    /// output. They are decoded from `decode_from_sample` and handed to no
    /// frame hook: the range before already showed them.
    pub lead_in: u64,
}

impl DecodeRange {
    /// The single range meaning "decode all of it" — what every path used
    /// before range-parallel decode existed, and the fallback whenever a
    /// source cannot be split safely.
    pub fn whole_source() -> Self {
        Self { start_sample: 0, end_sample: None, start_frame: 0, decode_from_sample: 0, lead_in: 0 }
    }

    /// A range that starts decoding at its own first sample, with no lead-in.
    pub fn new(start_sample: u64, end_sample: Option<u64>, start_frame: u64) -> Self {
        Self { start_sample, end_sample, start_frame, decode_from_sample: start_sample, lead_in: 0 }
    }

    /// The `sample_range` a pump config takes for this range: `None` for the
    /// whole source (nothing to skip), the range otherwise.
    pub fn sample_range(&self) -> Option<DecodeRange> {
        if *self == Self::whole_source() { None } else { Some(*self) }
    }

    /// The frames this range contributes (lead-in excluded), given the
    /// frames in the whole source and where the next range starts.
    pub fn frames(&self, next_start_frame: Option<u64>, total_frames: u64) -> u64 {
        next_start_frame.unwrap_or(total_frames).saturating_sub(self.start_frame)
    }
}

/// Split the source into at most `want` ranges that can be decoded in
/// parallel, one per GPU.
///
/// Returns `None` when the source cannot be split safely, and the caller
/// should decode it whole. That is the answer whenever:
///
/// - the codec is not one whose keyframes we can identify from the bitstream
///   (H.264 / H.265 today — see [`container::nal_mux::sample_is_keyframe`]),
/// - the source has too few keyframes to give every range one,
/// - or no keyframe lands on a multiple of `frames_per_chunk`.
///
/// # Why boundaries must land on a segment boundary
///
/// Each range's scaler groups `frames_per_chunk` frames into a segment and
/// numbers segments from a base. If a range began mid-segment, its first
/// segment would hold fewer frames than the rung's others, every rung would
/// have to make the same odd split for playback to stay aligned, and the base
/// index could no longer be computed as `start_frame / frames_per_chunk`.
/// Requiring the boundary to be both a keyframe *and* a multiple of the
/// segment length keeps segment numbering arithmetic and identical on every
/// rung.
///
/// One decoded frame per demuxed sample is assumed, which holds for the
/// progressive single-layer streams the pipeline accepts.
///
/// `lead_in` is the chunk lead-in margin, in frames (`0` for none). Each range
/// after the first then starts decoding at the latest keyframe at least that
/// far before its boundary and emits those `lead_in` frames ahead of its own
/// ([`DecodeRange::lead_in`]), so its first chunk gets the same lead-in a
/// whole-source decode gives it. A boundary with no such keyframe before it
/// starts cold, as every range did before.
pub fn plan_decode_ranges(
    input_data: &Bytes,
    codec_name: &str,
    frames_per_chunk: u32,
    want: usize,
    lead_in: u64,
) -> Option<Vec<DecodeRange>> {
    if want <= 1 || frames_per_chunk == 0 {
        return None;
    }
    let codec = nal_codec_for(codec_name)?;

    // Index pass: demux only, no decode. Record which sample indices may start
    // a range and how many samples there are.
    let mut demuxer = streaming::demux_streaming(input_data).ok()?;
    // A presentation edit (an MP4 edit list) hides decoded frames. A range's
    // first segment index counts *presented* frames, so a boundary is placed
    // by its presented index — and only after every hidden frame, so no range
    // needs to know what an earlier one skipped.
    let presentation = demuxer.video_presentation().cloned();
    // A frame the source holds for several periods (an AVI's dropped
    // frames) is several output frames: a sample's index no longer counts
    // the frames before it, so the source decodes whole.
    if demuxer.frame_repeats().is_some() {
        return None;
    }
    let mut keyframes: Vec<u64> = Vec::new();
    let mut total: u64 = 0;
    while let Ok(Some(sample)) = demuxer.next_video_sample() {
        if container::nal_mux::sample_is_keyframe(&sample.data, codec) {
            keyframes.push(total);
        }
        total += 1;
    }
    if total == 0 {
        return None;
    }

    let per_chunk = u64::from(frames_per_chunk);
    // Candidate boundaries `(sample, presented frame)`: a keyframe whose
    // presented index is a segment boundary. Index 0 is excluded because it is
    // the start of the first range, not a split.
    let candidates: Vec<(u64, u64)> = keyframes
        .iter()
        .copied()
        .filter_map(|k| {
            let frame = match &presentation {
                None => k,
                Some(p) => p.presented_index_after_hidden(k)?,
            };
            (frame > 0 && frame % per_chunk == 0).then_some((k, frame))
        })
        .collect();
    if candidates.is_empty() {
        return None;
    }

    // Aim for equal-length ranges and take the candidate nearest each target.
    // Duplicates collapse, so a source with few usable boundaries yields fewer
    // ranges rather than empty ones.
    let mut splits: Vec<(u64, u64)> = Vec::new();
    for n in 1..want {
        let target = total * n as u64 / want as u64;
        if let Some(best) = candidates.iter().copied().min_by_key(|(k, _)| k.abs_diff(target))
            && !splits.contains(&best)
        {
            splits.push(best);
        }
    }
    if splits.is_empty() {
        return None;
    }
    splits.sort_unstable();

    // Keyframes a lead-in may start from: `(sample, presented frame)` for
    // each one with every hidden frame behind it.
    let starts: Vec<(u64, u64)> = keyframes
        .iter()
        .copied()
        .filter_map(|k| match &presentation {
            None => Some((k, k)),
            Some(p) => p.presented_index_after_hidden(k).map(|f| (k, f)),
        })
        .collect();
    let with_lead_in = |start: u64, end: Option<u64>, start_frame: u64| -> DecodeRange {
        let mut range = DecodeRange::new(start, end, start_frame);
        if lead_in > 0
            && start_frame >= lead_in
            && let Some(&(from, _)) = starts.iter().rev().find(|&&(_, f)| f + lead_in <= start_frame)
        {
            range.decode_from_sample = from;
            range.lead_in = lead_in;
        }
        range
    };

    let mut ranges = Vec::with_capacity(splits.len() + 1);
    ranges.push(DecodeRange::new(0, splits.first().map(|&(s, _)| s), 0));
    for (i, &(split, split_frame)) in splits.iter().enumerate() {
        ranges.push(with_lead_in(split, splits.get(i + 1).map(|&(s, _)| s), split_frame));
    }

    Some(ranges)
}

/// The NAL family for a codec label, for the codecs whose keyframes and
/// parameter sets can be read out of a sample.
fn nal_codec_for(codec_name: &str) -> Option<container::nal_mux::NalMuxCodec> {
    match codec_name.to_ascii_lowercase().as_str() {
        "h264" | "avc" | "avc1" => Some(container::nal_mux::NalMuxCodec::H264),
        "h265" | "hevc" | "hvc1" | "hev1" => Some(container::nal_mux::NalMuxCodec::H265),
        _ => None,
    }
}

/// One clip of a splice: a decode config, its source bytes, and the **source
/// frame range** to keep. The first `start_frame` decoded frames are dropped
/// (the trim in-point); decoding stops once the source index reaches
/// `end_frame` (exclusive — the trim out-point). `end_frame = None` keeps the
/// clip to its end. A single full-range clip (`start_frame = 0`,
/// `end_frame = None`) is a plain, un-spliced transcode.
#[derive(Clone)]
pub struct ClipSource {
    pub cfg: DecodePumpConfig,
    pub input: Bytes,
    pub start_frame: u64,
    pub end_frame: Option<u64>,
}

impl ClipSource {
    /// A whole clip, no trim.
    pub fn whole(cfg: DecodePumpConfig, input: Bytes) -> Self {
        Self { cfg, input, start_frame: 0, end_frame: None }
    }
}

/// Single-input decode pump (no trim, no concat) — the common case. A thin
/// wrapper over [`run_spliced_decode_pump_blocking`] with one whole clip.
pub fn run_shared_decode_pump_blocking(
    cfg: DecodePumpConfig,
    input_data: Bytes,
    senders: Vec<tokio::sync::mpsc::Sender<VideoFrame>>,
    rt: tokio::runtime::Handle,
) -> Result<u64> {
    run_spliced_decode_pump_blocking(vec![ClipSource::whole(cfg, input_data)], senders, rt)
}

/// Spliced decode pump, designed for `tokio::task::spawn_blocking`. Decodes
/// each clip in order, **drops** frames outside the clip's `[start_frame,
/// end_frame)` source range (trim), and fans the kept frames out to all
/// `senders` **continuously across clips** (concat). The muxers time output
/// frames by count and order them by timestamp, so the join is gap-free and
/// the timeline zero-based as long as the timestamps keep rising across it:
/// each clip after the first has its timestamps carried on from the clip
/// before (`JoinedPts`).
///
/// If a sender's channel is closed (its rung gave up) the pump keeps going with
/// the rest; it stops only when *every* sender is closed. `rt` bridges into the
/// async `send().await`. Returns the total number of frames emitted.
pub fn run_spliced_decode_pump_blocking(
    clips: Vec<ClipSource>,
    senders: Vec<tokio::sync::mpsc::Sender<VideoFrame>>,
    rt: tokio::runtime::Handle,
) -> Result<u64> {
    // Everything this pump splits across threads on its own — its decoder's
    // pool, the filters' bands, the colour conversions' rows — stays within
    // the job's share of the machine (a range pump's caller may narrow it
    // further), so jobs running at once fit the machine together.
    codec::threads::with_budget(crate::thread_budget::per_job(), || run_clips(clips, senders, rt))
}

fn run_clips(
    clips: Vec<ClipSource>,
    senders: Vec<tokio::sync::mpsc::Sender<VideoFrame>>,
    rt: tokio::runtime::Handle,
) -> Result<u64> {
    let mut total: u64 = 0;
    let mut joined = JoinedPts::default();
    let result = (|| {
        for (clip_idx, clip) in clips.iter().enumerate() {
            joined.start_clip();
            match decode_clip(clip_idx, clip, &senders, &rt, &mut total, &mut joined)
                .with_context(|| format!("decoding splice clip {clip_idx}"))?
            {
                Flow::Continue => {}
                Flow::AllReceiversClosed => break,
            }
        }
        Ok(total)
    })();
    // Drop senders so receivers wake and exit.
    drop(senders);
    result
}

enum Flow {
    Continue,
    AllReceiversClosed,
}

/// Decode one clip, applying its trim range, fanning kept frames to `senders`
/// and advancing the shared output counter `total` and the joined timestamps.
fn decode_clip(
    clip_idx: usize,
    clip: &ClipSource,
    senders: &[tokio::sync::mpsc::Sender<VideoFrame>],
    rt: &tokio::runtime::Handle,
    total: &mut u64,
    joined: &mut JoinedPts,
) -> Result<Flow> {
    let cfg = &clip.cfg;
    // This clip's own normaliser, filter state included. A clip is a stream:
    // a temporal filter's history starts here and ends here, so a splice cut
    // never blends into the next clip and two pumps (ranges, GPUs) never see
    // each other's.
    let mut normalizer = FrameNormalizer::new(cfg)?;
    let mut demuxer =
        streaming::demux_streaming_shared(clip.input.clone())
            .context("demuxing clip for decode pump")?;
    let decoder =
        decode::create_decoder_on(&cfg.codec_name, cfg.info_for_decoder.clone(), cfg.gpu_index)
            .context("creating decoder for decode pump")?;
    // Wrapped here rather than at each consumer: every rung fed by this pump
    // wants the picture the right way up. A rotation of 0 returns the decoder
    // itself, so the common case pays nothing.
    let mut decoder = decode::RotatingDecoder::new(decoder, cfg.rotation_degrees);

    // The decode range, by demuxed sample index. Everything before it is
    // parsed and not decoded; the range ends with a flush of what the decoder
    // still holds, because those frames belong to this range.
    let range = cfg.sample_range.unwrap_or_else(DecodeRange::whole_source);
    let (start_sample, end_sample) = (range.decode_from_sample, range.end_sample);
    // Frames presented before this are decoded only as references for what
    // follows; from here to `range.start_frame` they are the lead-in.
    let emit_from = range.start_frame.saturating_sub(range.lead_in);

    // Absolute index of the next decoded frame in the whole source — a range
    // starting at sample `start_sample` decodes to frame `start_sample` first
    // (one frame per sample). Placed on the source's presentation edit, when
    // it has one, it gives the presented index the trim window counts in.
    let mut src_idx: u64 = start_sample;
    let presentation = demuxer.video_presentation().cloned();
    // Frames the source holds for more than one period (an AVI's dropped
    // frames) are shown once a period: the output stays on the source's clock
    // at a constant rate.
    let slots = demuxer.frame_repeats().map(FrameSlots::new);
    if let Some(s) = &slots {
        tracing::info!(
            frames = s.frames(),
            periods = s.periods(),
            "decode pump: frames the source holds for several periods are repeated (dropped frames)"
        );
    }
    if let Some(p) = &presentation {
        tracing::info!(
            hidden = p.hidden.len(),
            presented = p.presented,
            samples = p.samples,
            start_sample,
            "decode pump: honouring the source's video edit list"
        );
    }
    let mut sample_idx: u64 = 0;
    // Decoders number their output from 0, so a range's frames would restart
    // the timeline at every boundary — the timestamps of the whole decode are
    // the decoded index, which a range starting at `start_sample` reaches by
    // adding it.
    let lead = RangeLead { emit_from, own_from: range.start_frame, pts_offset: start_sample };

    // Parameter sets seen while skipping to the start of the range.
    //
    // mp4 keeps SPS/PPS in `avcC` extradata, so the demuxer emits them in-band
    // once at the top of the stream. A range starting anywhere else gets an IDR
    // with nothing to configure the decoder from, and a decoder in that state
    // does not fail — it returns zero frames, which then surfaces far away as a
    // rung missing two thirds of its segments.
    let nal_codec = nal_codec_for(&cfg.codec_name);
    let mut carried_param_sets: Vec<u8> = Vec::new();
    let mut param_sets_replayed = start_sample == 0;

    // Drain the decoder after `finish()`, at the end of the range or the clip.
    let drain = |decoder: &mut Box<dyn decode::Decoder>,
                     normalizer: &mut FrameNormalizer,
                     src_idx: &mut u64,
                     total: &mut u64,
                     joined: &mut JoinedPts|
     -> Result<Flow> {
        decoder.finish().context("decoder finish in decode pump")?;
        while let Some(frame) =
            decoder.decode_next().context("decoding frame after finish in decode pump")?
        {
            match handle_frame(clip_idx, clip, presentation.as_ref(), slots.as_ref(), normalizer, frame, senders, rt, src_idx, total, joined, lead)? {
                FrameAction::Continue => {}
                FrameAction::ClipDone => return Ok(Flow::Continue),
                FrameAction::StopAll => return Ok(Flow::AllReceiversClosed),
            }
        }
        Ok(Flow::Continue)
    };

    loop {
        match demuxer
            .next_video_sample()
            .context("demuxing next video sample in decode pump")?
        {
            Some(sample) => {
                let idx = sample_idx;
                sample_idx += 1;

                // Before our range: demux past it without decoding. The parse
                // is not wasted — it is also where the parameter sets are
                // picked up, so the decoder can be configured when the range
                // proper begins.
                if idx < start_sample {
                    if let Some(codec) = nal_codec {
                        let sets = container::nal_mux::extract_parameter_sets(&sample.data, codec);
                        if !sets.is_empty() {
                            carried_param_sets = sets;
                        }
                    }
                    continue;
                }
                // Past our range: flush what the decoder still holds and stop.
                if end_sample.is_some_and(|end| idx >= end) {
                    return drain(&mut decoder, &mut normalizer, &mut src_idx, total, joined);
                }
                // First sample of a range that started mid-stream: hand the
                // decoder the parameter sets in force here, ahead of the IDR —
                // unless this sample carries its own.
                if !param_sets_replayed {
                    param_sets_replayed = true;
                    let sample_has_own = nal_codec.is_some_and(|codec| {
                        !container::nal_mux::extract_parameter_sets(&sample.data, codec).is_empty()
                    });
                    if !carried_param_sets.is_empty() && !sample_has_own {
                        tracing::debug!(
                            start_sample,
                            bytes = carried_param_sets.len(),
                            "replaying parameter sets at decode-range start",
                        );
                        decoder
                            .push_sample(&carried_param_sets)
                            .context("pushing carried parameter sets at decode-range start")?;
                    }
                }

                decoder
                    .push_sample(&sample.data)
                    .context("pushing sample to decode pump decoder")?;
                while let Some(frame) =
                    decoder.decode_next().context("decoding frame in decode pump")?
                {
                    match handle_frame(clip_idx, clip, presentation.as_ref(), slots.as_ref(), &mut normalizer, frame, senders, rt, &mut src_idx, total, joined, lead)? {
                        FrameAction::Continue => {}
                        FrameAction::ClipDone => return Ok(Flow::Continue),
                        FrameAction::StopAll => return Ok(Flow::AllReceiversClosed),
                    }
                }
            }
            None => return drain(&mut decoder, &mut normalizer, &mut src_idx, total, joined),
        }
    }
}

/// Which decoded frames of a range are emitted: from `emit_from` on, with the
/// ones before `own_from` (the lead-in) handed to no frame hook.
#[derive(Debug, Clone, Copy)]
struct RangeLead {
    emit_from: u64,
    own_from: u64,
    /// Added to every decoded frame's timestamp.
    pts_offset: u64,
}

enum FrameAction {
    Continue,
    ClipDone,
    StopAll,
}

/// Timestamps carried across a splice's joins.
///
/// A decoder numbers its own output, so every clip's timestamps start again —
/// at 0, or at its trim in-point. The muxers put a frame in presentation order
/// by its timestamp's rank (`container::reorder`), and two clips' frames with
/// the same timestamp have no order: a spliced rung failed to finalize with
/// "presentation timestamp 30 appears on two samples". The first clip keeps its
/// timestamps; each later clip's run on from one past the last one handed out,
/// spaced as the clip's own were.
#[derive(Debug, Default)]
struct JoinedPts {
    /// One past the latest timestamp handed out.
    next: Option<u64>,
    /// The current clip's first timestamp, and where it lands.
    clip: Option<(u64, u64)>,
}

impl JoinedPts {
    /// A new clip: its first frame fixes where its timestamps land.
    fn start_clip(&mut self) {
        self.clip = None;
    }

    /// The timestamp a frame of the current clip carries in the joined stream.
    fn place(&mut self, pts: u64) -> u64 {
        let next = self.next;
        let (first, at) = *self.clip.get_or_insert((pts, next.unwrap_or(pts)));
        let out = at + pts.saturating_sub(first);
        self.next = Some(next.map_or(out + 1, |n| n.max(out + 1)));
        out
    }
}

/// Where each decoded frame lands in a constant-rate output when the source
/// holds some frames for several periods
/// ([`StreamingDemuxer::frame_repeats`](container::streaming::StreamingDemuxer::frame_repeats)):
/// decoded frame `i` fills output frames `starts[i]..starts[i + 1]`.
struct FrameSlots {
    starts: Vec<u64>,
}

impl FrameSlots {
    fn new(repeats: &[u32]) -> Self {
        let mut starts = Vec::with_capacity(repeats.len() + 1);
        let mut at = 0u64;
        starts.push(0);
        for &r in repeats {
            at += u64::from(r.max(1));
            starts.push(at);
        }
        Self { starts }
    }

    /// `(first output frame, output frames)` for decoded frame `i`; a frame
    /// past the table (a decoder that made more than the demuxer counted)
    /// follows the last one, once.
    fn span(&self, i: u64) -> (u64, u64) {
        match (self.starts.get(i as usize), self.starts.get(i as usize + 1)) {
            (Some(&a), Some(&b)) => (a, b - a),
            _ => (self.periods() + i.saturating_sub(self.frames()), 1),
        }
    }

    fn frames(&self) -> u64 {
        self.starts.len() as u64 - 1
    }

    fn periods(&self) -> u64 {
        self.starts[self.starts.len() - 1]
    }
}

/// Place one decoded frame on the source's presentation edit — a frame the
/// edit hides is dropped, a frame past its end ends the clip — and on the
/// output frames it fills (`slots`: one, unless the source holds it for
/// several periods), then apply the clip's trim range to those: drop output
/// frames before the in-point, signal `ClipDone` at the out-point, otherwise
/// normalize, carry its timestamp across the join and fan out.
#[allow(clippy::too_many_arguments)]
fn handle_frame(
    clip_idx: usize,
    clip: &ClipSource,
    presentation: Option<&container::edit::VideoPresentation>,
    slots: Option<&FrameSlots>,
    normalizer: &mut FrameNormalizer,
    frame: VideoFrame,
    senders: &[tokio::sync::mpsc::Sender<VideoFrame>],
    rt: &tokio::runtime::Handle,
    src_idx: &mut u64,
    total: &mut u64,
    joined: &mut JoinedPts,
    lead: RangeLead,
) -> Result<FrameAction> {
    let mut frame = frame;
    frame.pts += lead.pts_offset;
    let presented = match presentation.map(|p| p.place(*src_idx)) {
        None => *src_idx,
        Some(container::edit::FramePlace::Presented(index)) => index,
        Some(container::edit::FramePlace::Hidden) => {
            *src_idx += 1;
            return Ok(FrameAction::Continue);
        }
        Some(container::edit::FramePlace::PastEnd) => return Ok(FrameAction::ClipDone),
    };
    // A range that decodes from a keyframe ahead of its lead-in: the frames
    // before the lead-in are references only.
    if presented < lead.emit_from {
        *src_idx += 1;
        return Ok(FrameAction::Continue);
    }
    let hooked = presented >= lead.own_from;
    let Some(slots) = slots else {
        if clip.end_frame.is_some_and(|end| presented >= end) {
            return Ok(FrameAction::ClipDone); // reached the out-point
        }
        // Under a frame-rate cap a frame no output period starts on is
        // dropped, counting from the in-point so the output starts on it.
        let shown = presented >= clip.start_frame
            && clip.cfg.decimate.is_none_or(|r| {
                let rel = presented - clip.start_frame;
                out_index(rel + 1, r) > out_index(rel, r)
            });
        if shown {
            let hooks = &clip.cfg.hooks;
            let fps = clip.cfg.info_for_decoder.frame_rate;
            if hooked {
                hooks.emit_decoded_frame(clip_idx, presented, fps, &frame)?;
            }
            let mut normalized = normalizer.normalize(frame)?;
            if hooked {
                hooks.emit_encoder_frame(clip_idx, presented, fps, &normalized)?;
            }
            normalized.pts = joined.place(normalized.pts);
            if !fan_out(senders, normalized, rt)? {
                return Ok(FrameAction::StopAll);
            }
            *total += 1;
        }
        *src_idx += 1;
        return Ok(FrameAction::Continue);
    };
    // The output frames this one fills, clipped to the trim range; each copy
    // is timestamped with its output frame, so the copies rank in order.
    let (first, count) = slots.span(presented);
    if clip.end_frame.is_some_and(|end| first >= end) {
        return Ok(FrameAction::ClipDone); // reached the out-point
    }
    let kept = first.max(clip.start_frame)..clip.end_frame.map_or(first + count, |end| end.min(first + count));
    // Under a frame-rate cap, the source periods kept become the output
    // periods that start within them; each copy is timestamped with the
    // source period it starts in, so the copies still rank in order.
    let slots_out: Vec<u64> = match clip.cfg.decimate {
        None => kept.collect(),
        Some(r) if !kept.is_empty() => {
            let (a, b) = (kept.start - clip.start_frame, kept.end - clip.start_frame);
            (out_index(a, r)..out_index(b, r))
                .map(|o| clip.start_frame + ((o as f64 / r) - 1e-9).ceil().max(a as f64) as u64)
                .collect()
        }
        Some(_) => Vec::new(),
    };
    if !slots_out.is_empty() {
        let hooks = &clip.cfg.hooks;
        let fps = clip.cfg.info_for_decoder.frame_rate;
        if hooked {
            hooks.emit_decoded_frame(clip_idx, presented, fps, &frame)?;
        }
        let normalized = normalizer.normalize(frame)?;
        if hooked {
            hooks.emit_encoder_frame(clip_idx, presented, fps, &normalized)?;
        }
        for slot in slots_out {
            let mut copy = normalized.clone();
            copy.pts = joined.place(slot);
            if !fan_out(senders, copy, rt)? {
                return Ok(FrameAction::StopAll);
            }
            *total += 1;
        }
    }
    *src_idx += 1;
    Ok(FrameAction::Continue)
}

/// The colour space a clip's frames are converted as: the source's, as the
/// demuxer resolved it — container colour description, else the SPS VUI, else
/// the defaults (`container::demux::hdr`) — and not whatever the decoder
/// stamped on them.
///
/// Decoders disagree. The native h26x decoder repeats the `StreamInfo` it was
/// built with; NVDEC reports CUVID's own reading of the VUI; AMF says BT.709
/// whatever the stream says. The 8-bit SDR path keys its BT.601 → BT.709
/// matrix on `VideoFrame::color_space`, so before this the same file came out
/// converted or not depending on which card decoded it — a container tag
/// contradicting the VUI (or any BT.601 source on AMF) was a different
/// picture per decoder, under the same output tags.
///
/// H.264, HEVC, AV1, VP9 and MPEG-2 only
/// ([`container::demux::reads_bitstream_colour`]): those are the codecs whose
/// bitstream colour the demuxer reads, so for them the resolved colour is at
/// least what a decoder could see — and a standard-definition stream that
/// states no matrix is BT.601 by the demuxer's default whichever decoder
/// reads it. For the others a silent container resolves to the default and
/// says nothing about the stream, so the decoder's reading stays.
pub(crate) struct SourceColourTag {
    /// `None`: leave the decoder's tag alone.
    source: Option<ColorSpace>,
    /// Whether a decoder disagreeing with the source has been logged.
    told: bool,
}

impl SourceColourTag {
    fn for_config(cfg: &DecodePumpConfig) -> Self {
        Self::for_stream(&cfg.codec_name, &cfg.info_for_decoder)
    }

    /// The tag for a stream of `codec` whose demuxed header info is `info`.
    pub(crate) fn for_stream(codec: &str, info: &codec::frame::StreamInfo) -> Self {
        let resolved = nal_codec_for(codec).is_some()
            || container::demux::reads_bitstream_colour(&codec.to_ascii_lowercase());
        Self {
            source: resolved.then_some(info.color_space),
            told: false,
        }
    }

    /// `frame` tagged with the source's colour space. The first frame whose
    /// decoder said otherwise is logged, once per clip.
    pub(crate) fn apply(&mut self, mut frame: VideoFrame) -> VideoFrame {
        let Some(source) = self.source else {
            return frame;
        };
        if frame.color_space != source {
            if !self.told {
                self.told = true;
                tracing::info!(
                    decoder_color_space = ?frame.color_space,
                    source_color_space = ?source,
                    "decode pump: the decoder's colour tag differs from the source colour; converting as the source colour says"
                );
            }
            frame.color_space = source;
        }
        frame
    }
}

/// Everything the pump does to a decoded frame before fanning it out, for one
/// stream: the source-colour tag ([`SourceColourTag`]), the layout / tonemap /
/// SDR → HDR / bit-depth normalisation ([`normalize_frame`]) and the video
/// filters, with the state each keeps (a temporal filter's history, the
/// SDR → HDR tables).
///
/// The paths that decode a source outside the pump — `transcode_bytes` and
/// the per-title sample — build one from [`DecodePumpConfig::for_source`], so
/// a frame comes out the same whichever entry point decoded it. Before, each
/// did a subset of its own: `transcode_bytes` kept the decoder's colour tag,
/// re-matrixed a BT.601 source and still tagged it BT.601, and tonemapped
/// nothing; the per-title sample measured raw decoder frames.
pub(crate) struct FrameNormalizer {
    cfg: DecodePumpConfig,
    filters: codec::filter::FilterInstance,
    colour: SourceColourTag,
    sdr_to_hdr: Option<colorspace::SdrToHdr>,
}

impl FrameNormalizer {
    /// A normaliser for one stream decoded under `cfg`. Refuses, by name, an
    /// SDR → HDR mapping the source cannot take ([`colorspace::SdrToHdr::new`]).
    pub(crate) fn new(cfg: &DecodePumpConfig) -> Result<Self> {
        let filters = std::sync::Arc::clone(&cfg.filters).instantiate();
        if filters.chain().is_stateful() {
            tracing::info!(
                "video filters: temporal chain instantiated for this clip (frame history is per stream)"
            );
        }
        // An SDR source bound for a PQ / HLG output is mapped into the HDR
        // signal; the converter's tables are built once per stream.
        let sdr_to_hdr = match cfg.sdr_to_hdr {
            Some(target) => {
                let converter = colorspace::SdrToHdr::new(&cfg.source_color_metadata, target)
                    .context("mapping the SDR source into the HDR output")?;
                tracing::info!(
                    target_transfer = ?target,
                    source_transfer = ?cfg.source_color_metadata.transfer,
                    source_matrix = cfg.source_color_metadata.matrix_coefficients,
                    source_primaries = cfg.source_color_metadata.colour_primaries,
                    "decode pump: mapping the SDR source into HDR (BT.2408, SDR white at 203 cd/m2)"
                );
                Some(converter)
            }
            None => None,
        };
        Ok(Self {
            cfg: cfg.clone(),
            filters,
            colour: SourceColourTag::for_config(cfg),
            sdr_to_hdr,
        })
    }

    /// One decoded frame, normalised as the pump normalises it.
    pub(crate) fn normalize(&mut self, frame: VideoFrame) -> Result<VideoFrame> {
        let tagged = self.colour.apply(frame);
        normalize_frame(
            &self.cfg,
            &mut self.filters,
            self.sdr_to_hdr.as_ref(),
            tagged,
        )
    }
}

/// Rung-agnostic per-frame work: 4:4:4 → 4:2:0 downsample (if needed) then,
/// when the spec's color policy asks for it (`tonemap_to_sdr`), an HDR-aware
/// colorspace convert (tonemap PQ/HLG → SDR BT.709, identity for SDR). When
/// the policy is passthrough/HDR, the source keeps its colour but is still
/// brought onto a 4:2:0 layout the encoder takes (4:2:2 averaged, 12-bit
/// narrowed to 10) and, for an SDR source bound for an HDR output
/// (`sdr_to_hdr`, built from [`DecodePumpConfig::sdr_to_hdr`]), mapped into
/// that HDR signal. Last, the bit depth is matched to the encoder's
/// configured format. Per-rung scaling is NOT done here.
fn normalize_frame(
    cfg: &DecodePumpConfig,
    filters: &mut codec::filter::FilterInstance,
    sdr_to_hdr: Option<&colorspace::SdrToHdr>,
    frame: VideoFrame,
) -> Result<VideoFrame> {
    let downsampled = if cfg.needs_downsample {
        colorspace::downsample_444_to_420_frame_with(&frame, cfg.chroma_downsample)
            .context("shared decode pump 4:4:4 → 4:2:0 downsample")?
    } else {
        frame
    };
    let normalized = if !cfg.tonemap_to_sdr {
        // Passthrough / HDR output: preserve the source colour and (up to
        // the encoder's 10-bit ceiling) bit depth; only the layout changes.
        let layout = colorspace::normalize_layout_to_420(&downsampled)
            .context("shared decode pump chroma-layout normalise (passthrough)")?;
        match sdr_to_hdr {
            Some(converter) => converter
                .convert(&layout)
                .context("shared decode pump SDR → HDR mapping")?,
            None => layout,
        }
    } else {
        colorspace::convert_to_sdr_bt709(&downsampled, &cfg.source_color_metadata)
            .context("shared decode pump colorspace convert (HDR-aware)")?
    };
    let depth_matched = match_output_bit_depth(&normalized, cfg.output_pixel_format)?;
    // Video filters (crop/pad/flip/rotate/grayscale/overlay/colour/denoise)
    // run on the normalized 4:2:0 frame, before the per-rung scalers see it —
    // through this clip's own instance, so a temporal filter's history is
    // this stream's alone.
    if filters.is_empty() {
        Ok(depth_matched)
    } else {
        filters.apply(depth_matched).context("shared decode pump video filters")
    }
}

/// Bring a normalised 4:2:0 frame to the encoder's configured bit depth:
/// 10 → 8 narrows with rounding, 8 → 10 widens exactly, a match is a cheap
/// clone. Anything else is a pipeline bug worth naming rather than an
/// encoder rejection three stages later.
fn match_output_bit_depth(frame: &VideoFrame, output: PixelFormat) -> Result<VideoFrame> {
    if frame.format == output {
        return Ok(frame.clone());
    }
    match (frame.format, output) {
        (PixelFormat::Yuv420p10le, PixelFormat::Yuv420p) => {
            colorspace::convert_bit_depth_frame(frame, 8)
                .context("shared decode pump 10 → 8-bit narrowing for the 8-bit output")
        }
        (PixelFormat::Yuv420p, PixelFormat::Yuv420p10le) => {
            colorspace::convert_bit_depth_frame(frame, 10)
                .context("shared decode pump 8 → 10-bit widening for the 10-bit output")
        }
        (have, want) => bail!(
            "decode pump produced {have:?} but the encoder was configured for {want:?}"
        ),
    }
}

/// Number of frames timed per candidate when benchmarking decoders. Chosen so
/// the measurement amortises driver init yet stays well under a second per
/// candidate even on a modest GPU.
pub const DECODE_BENCH_FRAMES: usize = 120;

/// Benchmark each candidate GPU by decoding a short prefix of `input` on it and
/// return the fastest `gpu_index` (what `--decode-with-fastest` pins the pump
/// to). Construction + first-frame latency is excluded — the clock starts after
/// a small warmup — so the number reflects steady-state decode throughput, not
/// driver init. Candidates that fail to construct or decode are skipped;
/// returns `None` if no candidate produced frames or fewer than two candidates
/// were given (nothing to choose).
pub fn fastest_decode_gpu(
    codec_name: &str,
    info: &codec::frame::StreamInfo,
    input: &Bytes,
    candidates: &[u32],
    measure_frames: usize,
) -> Option<u32> {
    if candidates.len() < 2 {
        return candidates.first().copied();
    }
    let mut best: Option<(u32, f64)> = None;
    for &gpu in candidates {
        match bench_decode_gpu(codec_name, info, input, gpu, measure_frames) {
            Ok(Some(fps)) => {
                tracing::info!(
                    gpu_index = gpu,
                    fps = format!("{fps:.1}"),
                    "decode-with-fastest: benchmarked candidate"
                );
                if best.is_none_or(|(_, b)| fps > b) {
                    best = Some((gpu, fps));
                }
            }
            Ok(None) => {
                tracing::warn!(gpu_index = gpu, "decode-with-fastest: no frames; skipping candidate")
            }
            Err(e) => tracing::warn!(
                gpu_index = gpu,
                error = %e,
                "decode-with-fastest: bench failed; skipping candidate"
            ),
        }
    }
    if let Some((gpu, fps)) = best {
        tracing::info!(
            gpu_index = gpu,
            fps = format!("{fps:.1}"),
            "decode-with-fastest: selected fastest decode GPU"
        );
    }
    best.map(|(g, _)| g)
}

/// Decode up to `measure_frames` frames (after an 8-frame warmup) from `input`
/// on `gpu`, returning the measured fps — or `None` if it produced no frames.
fn bench_decode_gpu(
    codec_name: &str,
    info: &codec::frame::StreamInfo,
    input: &Bytes,
    gpu: u32,
    measure_frames: usize,
) -> Result<Option<f64>> {
    const WARMUP: usize = 8;
    let target = WARMUP + measure_frames;
    let mut demuxer = streaming::demux_streaming(input).context("demux for decode bench")?;
    let mut decoder = decode::create_decoder_on(codec_name, info.clone(), Some(gpu))
        .context("create decoder for bench")?;
    let mut decoded = 0usize;
    let mut clock: Option<Instant> = None;
    'outer: loop {
        match demuxer.next_video_sample().context("bench next sample")? {
            Some(s) => {
                decoder.push_sample(&s.data).context("bench push")?;
                while decoder.decode_next().context("bench decode")?.is_some() {
                    decoded += 1;
                    if decoded == WARMUP {
                        clock = Some(Instant::now());
                    }
                    if decoded >= target {
                        break 'outer;
                    }
                }
            }
            None => {
                decoder.finish().context("bench finish")?;
                while decoder.decode_next().context("bench drain")?.is_some() {
                    decoded += 1;
                    if decoded == WARMUP {
                        clock = Some(Instant::now());
                    }
                    if decoded >= target {
                        break 'outer;
                    }
                }
                break;
            }
        }
    }
    let measured = decoded.saturating_sub(WARMUP);
    Ok(match clock {
        Some(t) if measured > 0 => {
            let secs = t.elapsed().as_secs_f64();
            (secs > 0.0).then_some(measured as f64 / secs)
        }
        // Tiny clip (< WARMUP+1 frames): every candidate decodes the same few
        // frames, so return the count — equal across candidates, first wins.
        _ => (decoded > 0).then_some(decoded as f64),
    })
}

/// Fan one frame out to every sender. Cloning `VideoFrame` is cheap (inner
/// `Bytes` is `Arc`-backed). Returns `false` only if EVERY sender is closed.
///
/// A rung whose receiver is gone is skipped, quietly: the one warning is on
/// the frame that discovers it (the send that fails), and from then on
/// `is_closed` is true before the send is tried. Without that check an
/// aborted run — every scaler gone at once, the pump still draining the
/// frames it had in hand — logged one warning per rung per frame.
fn fan_out(
    senders: &[tokio::sync::mpsc::Sender<VideoFrame>],
    frame: VideoFrame,
    rt: &tokio::runtime::Handle,
) -> Result<bool> {
    let mut any_alive = false;
    for (idx, sender) in senders.iter().enumerate() {
        if sender.is_closed() {
            continue;
        }
        let frame_clone = frame.clone();
        let sender = sender.clone();
        let accepted = rt.block_on(async move { sender.send(frame_clone).await });
        match accepted {
            Ok(()) => any_alive = true,
            Err(_) => {
                tracing::warn!(rung_idx = idx, "shared decode pump: rung dropped its receiver");
            }
        }
    }
    Ok(any_alive)
}

#[cfg(test)]
mod tests {
    /// Each decoded frame's output frames run on from the last one's; a
    /// frame the table does not know (a decoder that made more frames than
    /// the demuxer counted) follows the last, once.
    #[test]
    fn frame_slots_place_each_frame_after_the_one_before() {
        let slots = super::FrameSlots::new(&[1, 2, 1, 3]);
        assert_eq!((slots.frames(), slots.periods()), (4, 7));
        let spans: Vec<(u64, u64)> = (0..6).map(|i| slots.span(i)).collect();
        assert_eq!(spans, [(0, 1), (1, 2), (3, 1), (4, 3), (7, 1), (8, 1)]);
        // A zero is not a count: every frame is shown at least once.
        assert_eq!(super::FrameSlots::new(&[0, 1]).span(1), (1, 1));
    }

    #[test]
    fn pump_output_matches_the_encoder_bit_depth() {
        use bytes::Bytes;
        use codec::frame::{ColorSpace, PixelFormat, VideoFrame};
        // A 10-bit SDR frame bound for an 8-bit encoder narrows; an 8-bit
        // frame bound for a 10-bit encoder widens; a match is untouched; a
        // layout mismatch is an error naming both sides.
        let ten: Vec<u8> = (0..(8 * 4 + 2 * 4 * 2) as u16)
            .map(|i| i * 17 % 1024)
            .flat_map(|v| v.to_le_bytes())
            .collect();
        let f10 = VideoFrame::new(Bytes::from(ten.clone()), 8, 4, PixelFormat::Yuv420p10le, ColorSpace::Bt709, 0);
        let f8 = super::match_output_bit_depth(&f10, PixelFormat::Yuv420p).expect("narrow");
        assert_eq!(f8.format, PixelFormat::Yuv420p);
        assert_eq!(f8.data.len(), 8 * 4 * 3 / 2);
        assert_eq!(f8.data[1], ((17u32 + 2) >> 2) as u8);
        let back = super::match_output_bit_depth(&f8, PixelFormat::Yuv420p10le).expect("widen");
        assert_eq!(back.format, PixelFormat::Yuv420p10le);
        assert_eq!(back.data.len(), ten.len());
        let same = super::match_output_bit_depth(&f10, PixelFormat::Yuv420p10le).expect("same");
        assert_eq!(same.data, f10.data);
        let f422 = VideoFrame::new(Bytes::from(vec![0u8; 8 * 4 * 2]), 8, 4, PixelFormat::Yuv422p, ColorSpace::Bt709, 0);
        let err = super::match_output_bit_depth(&f422, PixelFormat::Yuv420p).expect_err("layout mismatch");
        assert!(format!("{err:#}").contains("Yuv422p"), "{err:#}");
    }

    /// Clips that each number their frames from their own in-point, as a
    /// decoder does — `clipA@1-3` from 30, `clipB@0.5-2.5` from 15 — join into
    /// one run of distinct, rising timestamps with no gap at either join. The
    /// first clip's timestamps are untouched, so a job of one clip is exactly
    /// what it was, gaps and all.
    #[test]
    fn a_joined_clip_carries_its_timestamps_on_from_the_clip_before() {
        let mut joined = super::JoinedPts::default();
        let mut out = Vec::new();
        for clip in [30u64..90, 15..75, 0..3] {
            joined.start_clip();
            out.extend(clip.map(|pts| joined.place(pts)));
        }
        assert_eq!(out, (30..30 + 60 + 60 + 3).collect::<Vec<u64>>());

        let mut one = super::JoinedPts::default();
        one.start_clip();
        assert_eq!([7u64, 8, 10].map(|pts| one.place(pts)), [7, 8, 10]);
        // A later clip keeps its own spacing from where it lands.
        one.start_clip();
        assert_eq!([100u64, 102].map(|pts| one.place(pts)), [11, 13]);
    }

    use super::*;
    use codec::frame::VideoFrame;

    /// `RIVET_TEST_MEDIA` env override, else the workspace `test_media/` dir —
    /// the same lookup the integration tests use. The corpus is fetched on
    /// demand and never committed, so a missing file is a skip, not a failure.
    fn read_test_media(name: &str) -> Option<Bytes> {
        let dir = match std::env::var_os("RIVET_TEST_MEDIA") {
            Some(dir) => std::path::PathBuf::from(dir),
            None => std::path::Path::new(env!("CARGO_MANIFEST_DIR"))
                .parent()?
                .parent()?
                .join("test_media"),
        };
        std::fs::read(dir.join(name)).ok().map(Bytes::from)
    }

    /// Demux only: which sample indices are keyframes, and how many there are.
    fn h264_keyframes(input: &Bytes) -> (Vec<u64>, u64) {
        let mut demuxer = streaming::demux_streaming(input).expect("demux");
        let mut keyframes = Vec::new();
        let mut total = 0u64;
        while let Some(s) = demuxer.next_video_sample().expect("sample") {
            if container::nal_mux::sample_is_keyframe(
                &s.data,
                container::nal_mux::NalMuxCodec::H264,
            ) {
                keyframes.push(total);
            }
            total += 1;
        }
        (keyframes, total)
    }

    /// A pump config for `codec` whose source the demuxer resolved to
    /// `color_space`; nothing else in it does anything.
    fn tagging_config(codec: &str, color_space: ColorSpace) -> DecodePumpConfig {
        let matrix = if color_space == ColorSpace::Bt601 {
            6
        } else {
            1
        };
        let info = codec::frame::StreamInfo {
            codec: codec.into(),
            width: 8,
            height: 4,
            frame_rate: 30.0,
            duration: 1.0,
            pixel_format: PixelFormat::Yuv420p,
            color_space,
            total_frames: 1,
            bitrate: 0,
            color_metadata: ColorMetadata {
                matrix_coefficients: matrix,
                ..Default::default()
            },
        };
        DecodePumpConfig {
            codec_name: codec.into(),
            source_color_metadata: info.color_metadata,
            info_for_decoder: info,
            source_pixel_format: PixelFormat::Yuv420p,
            needs_downsample: false,
            chroma_downsample: Default::default(),
            output_pixel_format: PixelFormat::Yuv420p,
            tonemap_to_sdr: true,
            sdr_to_hdr: None,
            gpu_index: None,
            sample_range: None,
            rotation_degrees: 0,
            filters: std::sync::Arc::new(
                codec::filter::FilterChain::prepare(&[]).expect("empty chain"),
            ),
            decimate: None,
            hooks: crate::hooks::Hooks::default(),
        }
    }

    /// The same decoded picture converts the same way whichever decoder
    /// tagged it: NVDEC reporting a VUI the container contradicts, AMF
    /// reporting BT.709 for everything, h26x repeating the header.
    #[test]
    fn frames_convert_as_the_source_colour_says_whatever_the_decoder_tagged() {
        // Saturated chroma, so the BT.601 → BT.709 matrix visibly moves it.
        let mut data = vec![120u8; 8 * 4];
        data.extend(vec![60u8; 4 * 2]);
        data.extend(vec![200u8; 4 * 2]);
        let frame =
            |cs| VideoFrame::new(Bytes::from(data.clone()), 8, 4, PixelFormat::Yuv420p, cs, 0);
        let normalize = |cfg: &DecodePumpConfig, f: VideoFrame| {
            let mut filters = std::sync::Arc::clone(&cfg.filters).instantiate();
            let mut colour = SourceColourTag::for_config(cfg);
            let out = normalize_frame(cfg, &mut filters, None, colour.apply(f)).expect("normalize");
            (out, colour.told)
        };

        // Resolved BT.709 (the container's tag), a decoder that read BT.601
        // out of the VUI: nothing to convert.
        let (out, told) = normalize(
            &tagging_config("h264", ColorSpace::Bt709),
            frame(ColorSpace::Bt601),
        );
        assert_eq!(
            out.data, data,
            "a BT.709 source was matrixed because its decoder said BT.601"
        );
        assert_eq!(out.color_space, ColorSpace::Bt709);
        assert!(told, "the disagreement is logged");

        // Resolved BT.601, a decoder that said BT.709: converted, exactly as a
        // frame the decoder had tagged BT.601 is.
        let cfg601 = tagging_config("h265", ColorSpace::Bt601);
        let want = colorspace::convert_to_sdr_bt709(
            &frame(ColorSpace::Bt601),
            &cfg601.source_color_metadata,
        )
        .expect("convert");
        assert_ne!(
            want.data, data,
            "the fixture must be one the matrix changes"
        );
        let (out, told) = normalize(&cfg601, frame(ColorSpace::Bt709));
        assert_eq!(
            out.data, want.data,
            "a BT.601 source went unconverted because its decoder said BT.709"
        );
        assert!(told);

        // A decoder that agrees has nothing to log.
        let (_, told) = normalize(&cfg601, frame(ColorSpace::Bt601));
        assert!(!told);

        // AV1 (like VP9 and MPEG-2) states its colour in its bitstream, which
        // the demuxer reads: its resolved colour holds too. An untagged
        // standard-definition stream resolved BT.601 is converted, whatever
        // the decoder said.
        let av1_601 = tagging_config("av1", ColorSpace::Bt601);
        let (out, told) = normalize(&av1_601, frame(ColorSpace::Bt709));
        assert_eq!(out.data, want.data);
        assert!(told);

        // A codec whose bitstream colour the demuxer does not read keeps the
        // decoder's reading: the default header says nothing about the stream.
        let (out, told) = normalize(
            &tagging_config("vp8", ColorSpace::Bt709),
            frame(ColorSpace::Bt601),
        );
        assert_eq!(out.data, want.data);
        assert!(!told);
    }

    /// An SDR source under an HDR output policy leaves the pump as the HDR
    /// signal: white at PQ 58 % (code 573), not an 8-bit SDR picture widened
    /// to 10 bits and relabelled.
    #[test]
    fn an_sdr_source_bound_for_hdr_leaves_the_pump_mapped() {
        let cfg = DecodePumpConfig {
            output_pixel_format: PixelFormat::Yuv420p10le,
            tonemap_to_sdr: false,
            sdr_to_hdr: Some(TransferFn::St2084),
            ..tagging_config("h264", ColorSpace::Bt709)
        };
        let mut data = vec![235u8; 8 * 4];
        data.extend(vec![128u8; 2 * 4 * 2]);
        let white = VideoFrame::new(
            Bytes::from(data),
            8,
            4,
            PixelFormat::Yuv420p,
            ColorSpace::Bt709,
            0,
        );
        let converter = colorspace::SdrToHdr::new(&cfg.source_color_metadata, TransferFn::St2084)
            .expect("an SDR BT.709 source maps");
        let mut filters = std::sync::Arc::clone(&cfg.filters).instantiate();
        let out = normalize_frame(&cfg, &mut filters, Some(&converter), white.clone())
            .expect("normalize");
        assert_eq!(
            (out.format, out.color_space),
            (PixelFormat::Yuv420p10le, ColorSpace::Bt2020)
        );
        assert_eq!(
            u16::from_le_bytes([out.data[0], out.data[1]]),
            573,
            "SDR white in PQ"
        );

        // Without the mapping the same frame is only widened: 235 << 2.
        let out = normalize_frame(&cfg, &mut filters, None, white).expect("normalize");
        assert_eq!(u16::from_le_bytes([out.data[0], out.data[1]]), 940);
    }

    #[test]
    fn a_whole_source_range_is_the_no_op_it_claims_to_be() {
        assert_eq!(DecodeRange::whole_source().sample_range(), None);
        assert_eq!(
            DecodeRange::new(120, None, 120).sample_range(),
            Some(DecodeRange::new(120, None, 120))
        );
    }

    #[test]
    fn a_single_range_or_an_unfamiliar_codec_is_not_split() {
        let input = Bytes::from_static(b"not a video");
        assert!(plan_decode_ranges(&input, "h264", 60, 1, 0).is_none(), "want=1 is no split");
        assert!(plan_decode_ranges(&input, "av1", 60, 4, 0).is_none(), "no keyframe test for av1");
        assert!(plan_decode_ranges(&input, "h264", 0, 4, 0).is_none(), "a zero chunk is no grid");
    }

    #[test]
    fn ranges_start_on_keyframes_that_fall_on_segment_boundaries() {
        // The two properties everything downstream relies on: a range can be
        // decoded from its first sample alone, and its first segment index is
        // `start_frame / frames_per_chunk` exactly.
        let Some(input) = read_test_media("bbb_h264_360p_short.mp4") else {
            eprintln!("SKIP: test_media/bbb_h264_360p_short.mp4 not present");
            return;
        };
        let (keyframes, total) = h264_keyframes(&input);
        assert!(keyframes.len() > 1, "the sample needs several keyframes to split on");

        // Pick a chunk length that divides at least one keyframe past the
        // first, so the planner has a boundary to use.
        let per_chunk = keyframes
            .iter()
            .copied()
            .find(|&k| k > 0)
            .map(|k| k as u32)
            .expect("a second keyframe");

        let ranges = plan_decode_ranges(&input, "h264", per_chunk, 3, 0)
            .expect("a splittable source with want=3 should split");
        assert!(ranges.len() >= 2 && ranges.len() <= 3, "ranges: {ranges:?}");

        // Contiguous and covering: each range starts where the last ended, the
        // first at 0, the last open-ended.
        assert_eq!(ranges[0].start_sample, 0);
        assert!(ranges.last().unwrap().end_sample.is_none());
        for pair in ranges.windows(2) {
            assert_eq!(pair[0].end_sample, Some(pair[1].start_sample), "gap or overlap: {ranges:?}");
        }
        for r in &ranges {
            assert!(keyframes.contains(&r.start_sample), "{r:?} does not start on a keyframe");
            assert_eq!(r.start_sample % u64::from(per_chunk), 0, "{r:?} is off the segment grid");
            assert_eq!(r.start_frame, r.start_sample, "one frame per sample");
            assert!(r.start_sample < total);
        }
    }

    #[test]
    fn a_frame_rate_cap_keeps_the_duration() {
        // 60 → 24: two frames of every five, evenly — the first frame of
        // each output period.
        let r = decimation(60.0, Some(24.0)).expect("a cap below the source");
        let kept: Vec<u64> = (0..10).filter(|&k| out_index(k + 1, r) > out_index(k, r)).collect();
        assert_eq!(kept, vec![0, 2, 5, 7]);
        assert_eq!(output_frames(10, Some(r)), 4);
        // A cap at or above the source's rate, no cap, or an unknown source
        // rate keep every frame.
        assert_eq!(decimation(30.0, Some(30.0)), None);
        assert_eq!(decimation(30.0, Some(60.0)), None);
        assert_eq!(decimation(30.0, None), None);
        assert_eq!(decimation(0.0, Some(5.0)), None);
        assert_eq!(output_frames(1025, None), 1025);
        // 1025 frames over 17.5 s (58.58 fps) capped at 5 fps is 88 frames:
        // 17.6 s at 5 fps, not 205 s.
        let r = decimation(58.584_688_797_275_77, Some(5.0)).expect("capped");
        let n = output_frames(1025, Some(r));
        assert_eq!(n, 88);
        assert!(((n as f64 / 5.0) - 17.5).abs() < 0.2);
        // Exact on an integer ratio across a long run: no drift.
        assert_eq!(output_frames(3_600_000, decimation(60.0, Some(30.0))), 1_800_000);
    }

    #[test]
    fn a_capped_pump_keeps_the_frame_starting_each_output_period() {
        // Half the rate: the pump keeps source frames 0, 2, 4, … — the same
        // pictures a whole decode makes at those indices — and as many as
        // `output_frames` says, which is what the muxers and the chunk
        // planner count on.
        let Some(input) = read_test_media("bbb_h264_360p_short.mp4") else {
            eprintln!("SKIP: test_media/bbb_h264_360p_short.mp4 not present");
            return;
        };
        let header = streaming::demux_streaming(&input).expect("demux").header().clone();
        let base = DecodePumpConfig {
            codec_name: header.codec.clone(),
            info_for_decoder: header.info.clone(),
            source_color_metadata: header.info.color_metadata,
            source_pixel_format: header.info.pixel_format,
            needs_downsample: false,
            chroma_downsample: Default::default(),
            output_pixel_format: header.info.pixel_format,
            tonemap_to_sdr: true,
            sdr_to_hdr: None,
            gpu_index: None,
            sample_range: None,
            rotation_degrees: header.rotation_degrees,
            filters: std::sync::Arc::new(codec::filter::FilterChain::prepare(&[]).expect("empty chain")),
            decimate: None,
            hooks: crate::hooks::Hooks::default(),
        };
        let whole = match pump_frames(base.clone(), input.clone()) {
            Ok(frames) => frames,
            Err(e) => {
                eprintln!("SKIP: no H.264 decoder on this host/build ({e:#})");
                return;
            }
        };
        let capped = pump_frames(
            DecodePumpConfig { decimate: decimation(header.info.frame_rate, Some(header.info.frame_rate / 2.0)), ..base },
            input,
        )
        .expect("capped decode");
        assert_eq!(capped.len() as u64, output_frames(whole.len() as u64, Some(0.5)));
        for (i, frame) in capped.iter().enumerate() {
            let source = &whole[i * 2];
            assert_eq!(frame.pts, source.pts, "output frame {i} is not source frame {}", i * 2);
            assert_eq!(frame.data, source.data, "output frame {i}'s picture differs from source frame {}", i * 2);
        }
    }

    /// Decode with the pump under `cfg`, collecting every frame it emits.
    fn pump_frames(cfg: DecodePumpConfig, input: Bytes) -> Result<Vec<VideoFrame>> {
        let rt = tokio::runtime::Builder::new_multi_thread()
            .worker_threads(2)
            .enable_all()
            .build()
            .expect("runtime");
        let (tx, mut rx) = tokio::sync::mpsc::channel::<VideoFrame>(4);
        let handle = rt.handle().clone();
        let pump =
            std::thread::spawn(move || run_shared_decode_pump_blocking(cfg, input, vec![tx], handle));
        let frames = rt.block_on(async move {
            let mut out = Vec::new();
            while let Some(f) = rx.recv().await {
                out.push(f);
            }
            out
        });
        pump.join().expect("pump thread")?;
        Ok(frames)
    }

    #[test]
    fn decoding_in_ranges_yields_the_frames_of_decoding_whole() {
        // The claim range-parallel decode rests on: two pumps over two ranges
        // produce, between them, exactly the frames one pump over the whole
        // source produces — same count, same pixels, in order. This is what
        // the parameter-set replay is for: without it the second range decodes
        // to nothing, and the ladder is missing everything after the split.
        let Some(input) = read_test_media("bbb_h264_360p_short.mp4") else {
            eprintln!("SKIP: test_media/bbb_h264_360p_short.mp4 not present");
            return;
        };
        let header = streaming::demux_streaming(&input).expect("demux").header().clone();
        let base = DecodePumpConfig {
            codec_name: header.codec.clone(),
            info_for_decoder: header.info.clone(),
            source_color_metadata: header.info.color_metadata,
            source_pixel_format: header.info.pixel_format,
            needs_downsample: false,
            chroma_downsample: Default::default(),
            output_pixel_format: header.info.pixel_format,
            tonemap_to_sdr: true,
            sdr_to_hdr: None,
            gpu_index: None,
            sample_range: None,
            rotation_degrees: header.rotation_degrees,
            filters: std::sync::Arc::new(codec::filter::FilterChain::prepare(&[]).expect("empty chain")),
            decimate: None,
            hooks: crate::hooks::Hooks::default(),
        };

        let whole = match pump_frames(base.clone(), input.clone()) {
            Ok(frames) => frames,
            Err(e) => {
                eprintln!("SKIP: no H.264 decoder on this host/build ({e:#})");
                return;
            }
        };
        assert!(!whole.is_empty());

        let (keyframes, _) = h264_keyframes(&input);
        let per_chunk =
            keyframes.iter().copied().find(|&k| k > 0).expect("a second keyframe") as u32;
        let ranges = plan_decode_ranges(&input, "h264", per_chunk, 2, 0).expect("splits in two");
        assert_eq!(ranges.len(), 2, "{ranges:?}");

        let mut joined = Vec::new();
        for range in &ranges {
            let cfg = DecodePumpConfig { sample_range: range.sample_range(), ..base.clone() };
            let frames = pump_frames(cfg, input.clone()).expect("range decodes");
            assert!(
                !frames.is_empty(),
                "range {range:?} decoded nothing — parameter sets not replayed?"
            );
            joined.extend(frames);
        }

        assert_eq!(joined.len(), whole.len(), "frame count differs between whole and ranged decode");
        for (i, (a, b)) in whole.iter().zip(joined.iter()).enumerate() {
            assert_eq!(
                (a.width, a.height, a.format),
                (b.width, b.height, b.format),
                "frame {i} shape"
            );
            assert_eq!(a.data, b.data, "frame {i} pixels differ between whole and ranged decode");
            assert_eq!(a.pts, b.pts, "frame {i} timestamp differs between whole and ranged decode");
        }
    }
}
