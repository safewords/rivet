use std::sync::Arc;

use anyhow::{Context, Result, bail};
use bytes::Bytes;

use codec::encode::{self, EncoderBackend, EncoderConfig};
use codec::frame::{ColorMetadata, VideoCodec, VideoFrame};
use container::demux::subtitle::SubtitleTrack;
use container::streaming::DemuxHeader;

use crate::decode_pump::{self, ClipSource};
use crate::multigpu::{self, MultiGpuParams, RungPackets};
use crate::progress::{ProgressSink, RungProgress, RungStatus};
use crate::spec::{Container, OutputSpec, Rung};
use crate::validate::needs_chroma_downsample;

use super::{RungArtifact, RungOutput, FRAME_CHANNEL_CAPACITY, report_rung_error};
use super::audio::PreparedAudio;
use super::file_mux::FileMuxer;
use super::splice::{trim_frame, trim_audio};

// ---------------------------------------------------------------------------
// SingleFile: decode-once fan-out to per-rung MP4 workers
// ---------------------------------------------------------------------------

#[allow(clippy::too_many_arguments)]
pub(super) async fn run_single_file(
    input: Bytes,
    spec: &OutputSpec,
    header: &DemuxHeader,
    frame_rate: f64,
    frames_total: Option<u64>,
    audio: Option<&PreparedAudio>,
    subtitles: &[SubtitleTrack],
    filter_chain: Arc<codec::filter::FilterChain>,
    sink: Arc<dyn ProgressSink>,
    // The source's late video start `(ticks, timescale)`; `(0, 1)` for none.
    video_delay: (u64, u32),
) -> Result<Vec<RungOutput>> {
    // When the frame count is known and the host has more than one GPU, run the
    // multi-GPU engine for single-file too: decode once, chunk each rung at
    // GOP boundaries, encode the chunks across all GPUs (fair lease pool +
    // helper dispatch + cross-vendor codec invariant), then stitch the packets,
    // in segment order, into one MP4 per rung. On a single-GPU host (or unknown
    // frame count) the serial path below is used unchanged — no chunk overhead.
    // `frame_rate` is the output's, after any cap; frame indices and trims
    // count on the source's clock, and a cap below it drops frames.
    let source_fps = if header.info.frame_rate > 0.0 { header.info.frame_rate } else { frame_rate };
    let decimate = decode_pump::decimation(header.info.frame_rate, spec.max_frame_rate);
    let total_input_frames = decode_pump::output_frames(
        if header.info.total_frames > 0 {
            header.info.total_frames
        } else {
            (header.info.duration * source_fps).round().max(0.0) as u64
        },
        decimate,
    );
    // A policy that leaves nothing to encode on is refused here, by name,
    // before a frame is decoded — see `gpu_pool_for_serial`.
    let (_, output_pixel_format) =
        spec.resolve_output(header.info.color_metadata, header.info.pixel_format);
    let gpu_pool =
        multigpu::gpu_pool_for_serial_job(spec, output_pixel_format)?;
    // `RIVET_FORCE_CHUNKED=1` runs the chunk-and-stitch engine on a one-GPU
    // host. It exists to verify the chunked path — seams, the per-chunk IDR,
    // the encoder session pool — on a machine with a single card, where the
    // rule below would otherwise route every job to the serial encoder and
    // leave that machinery untested. Not a performance setting: one card
    // gets no parallelism from it, only the chunk overhead.
    let force_chunked = std::env::var("RIVET_FORCE_CHUNKED").is_ok_and(|v| v == "1");
    if force_chunked {
        tracing::info!(
            gpu_pool_capacity = gpu_pool.capacity(),
            "RIVET_FORCE_CHUNKED=1: using the chunk-and-stitch engine regardless of GPU count"
        );
    }
    if spec.encode_policy.spreads()
        && total_input_frames > 0
        && (gpu_pool.capacity() > 1 || (force_chunked && gpu_pool.capacity() == 1))
        // Trim/splice jobs take the serial path: the multi-GPU chunker sizes its
        // chunks from the full source frame count, which a trim invalidates.
        && spec.trim_start.is_none()
        && spec.trim_end.is_none()
        // Only the web set chunks: the other codecs encode in software, one
        // encoder per rung (`VideoCodecPolicy::chunkable`).
        && spec.video_codec.chunkable()
    {
        // The chunk-and-stitch path's codec invariant now handles av1C / avcC /
        // hvcC, so AV1, H.264, and H.265 all chunk across GPUs. Each chunk is a
        // closed GOP (first frame an IDR), so stitched H.264/H.265 streams reset
        // refs cleanly at every chunk boundary.
        //
        // The chunk workers lease their encoders from the pool and never build
        // the backend pinned by `TRANSCODE_ENCODER_BACKEND`, which `validate`
        // counted for a single-file job: check the output again without it,
        // here, before a frame is decoded — the spec's own ask and what this
        // source makes of it.
        spec.check_encoder_caps(None).context("invalid OutputSpec")?;
        spec.check_source_against(
            header.info.color_metadata,
            header.info.pixel_format,
            &codec::encode::compiled_encode_backends(),
            None,
        )
        .context("invalid OutputSpec")?;
        // The chunk workers lease cards and build their encoders for the
        // output's format on them, with no fallback: lease from a pool of
        // cards that take that format (software slots in their place when
        // none does), not the serial pool, which is judged at the codec.
        let gpu_pool =
            multigpu::gpu_pool_for_job(spec, output_pixel_format)?;
        // Bitrate rungs are coded by the software encoder only; the chunk
        // workers lease from this pool and never read the pin.
        multigpu::check_rate_pool(spec, &gpu_pool, output_pixel_format, None)?;
        return run_single_file_multigpu(
            input,
            spec,
            header,
            frame_rate,
            total_input_frames,
            audio,
            subtitles,
            gpu_pool,
            filter_chain,
            sink,
            video_delay,
        )
        .await;
    }

    // Serial path: encode on the policy's GPU — the pool's first card, pinned
    // by index AND vendor, for a policy that names silicon (`family:VENDOR`,
    // `gpu:N`), so the dispatcher cannot slide to another vendor or to
    // software if that card declines; auto for an unpinned policy, as before.
    // Decode follows the explicit decode_gpu override, else the same GPU.
    let (encode_gpu, encode_vendor) = multigpu::serial_target(spec.encode_policy, &gpu_pool);
    // Bitrate rungs are coded by the software encoder only, which the serial
    // encoder builds by name when pinned to it whatever the pool holds.
    multigpu::check_rate_pool(spec, &gpu_pool, output_pixel_format, encoder_backend_override())?;
    let decode_gpu = spec.decode_policy.gpu_index().or(encode_gpu);
    let (output_color_metadata, output_pixel_format) =
        spec.resolve_output(header.info.color_metadata, header.info.pixel_format);
    let base_cfg = EncoderConfig {
        frame_rate,
        pixel_format: output_pixel_format,
        color_metadata: output_color_metadata,
        gpu_index: encode_gpu,
        gpu_vendor: encode_vendor,
        codec: spec.video_codec.codec(),
        ..EncoderConfig::default()
    };
    let pump_cfg = crate::decode_pump::DecodePumpConfig {
        codec_name: header.codec.clone(),
        info_for_decoder: header.info.clone(),
        source_color_metadata: header.info.color_metadata,
        source_pixel_format: header.info.pixel_format,
        needs_downsample: needs_chroma_downsample(header.info.pixel_format),
        chroma_downsample: spec.chroma_downsample,
        output_pixel_format,
        tonemap_to_sdr: spec.tonemaps(),
        sdr_to_hdr: crate::spec::sdr_into_hdr(
            spec.tonemaps(),
            &header.info.color_metadata,
            &output_color_metadata,
        ),
        gpu_index: decode_gpu,
        sample_range: None,
        rotation_degrees: header.rotation_degrees,
        filters: Arc::clone(&filter_chain),
        decimate,
        hooks: spec.hooks.clone(),
    };
    // Splice trim: seconds → source frame indices at the output cadence, as a
    // half-open `[start_frame, end_frame)`. `ceil` makes the bounds exact for
    // any (possibly non-integer) detected fps — keep frame n iff
    // `start <= n/fps < end`. The pump drops out-of-range frames and the muxer
    // re-numbers the kept frames from zero (trimmed + rebased).
    let start_frame = trim_frame(spec.trim_start, source_fps).unwrap_or(0);
    let end_frame = trim_frame(spec.trim_end, source_fps);
    // Progress is reported against the trimmed length, not the full source,
    // in output frames.
    let effective_total = match (end_frame, frames_total) {
        (Some(end), _) => Some(end.saturating_sub(start_frame)),
        (None, Some(t)) => Some(t.saturating_sub(start_frame)),
        (None, None) => None,
    }
    .map(|n| decode_pump::output_frames(n, decimate));
    // Trim the prepared audio to the same window so A/V stay aligned.
    let trimmed_audio = trim_audio(audio, spec.trim_start, spec.trim_end);
    let clip = ClipSource { cfg: pump_cfg, input, start_frame, end_frame };
    run_serial_single_file(
        vec![clip],
        spec,
        base_cfg,
        frame_rate,
        effective_total,
        trimmed_audio,
        subtitles.to_vec(),
        sink,
        video_delay,
    )
    .await
}

/// Serial single-file encode of one or more (pre-trimmed) clips: the spliced
/// decode pump concatenates the clips' kept frames into one continuous stream,
/// and each rung worker encodes that stream into one MP4. Shared by the
/// single-input trim path and `run_splice_job` (multi-clip concat).
#[allow(clippy::too_many_arguments)]
pub(super) async fn run_serial_single_file(
    clips: Vec<ClipSource>,
    spec: &OutputSpec,
    base_cfg: EncoderConfig,
    frame_rate: f64,
    effective_total: Option<u64>,
    audio: Option<PreparedAudio>,
    subtitles: Vec<SubtitleTrack>,
    sink: Arc<dyn ProgressSink>,
    // The (first clip's) late video start `(ticks, timescale)`; `(0, 1)` for none.
    video_delay: (u64, u32),
) -> Result<Vec<RungOutput>> {
    let backend_override = encoder_backend_override();
    let container = spec.container;
    let rt = tokio::runtime::Handle::current();

    // The rungs encode at once, one encoder each. A software encoder left
    // at `threads: 0` sizes its pool to the whole machine, so N rungs meant N
    // × every core — 96 threads on 32 cores for a three-rung ladder. Hand
    // each rung its share instead; the hardware backends do not read
    // `threads` and are unaffected. An explicit budget from the caller stays.
    let base_cfg = if base_cfg.threads == 0 {
        EncoderConfig { threads: serial_threads_per_rung(spec.rungs.len()), ..base_cfg }
    } else {
        base_cfg
    };

    let mut senders = Vec::with_capacity(spec.rungs.len());
    let mut handles = Vec::with_capacity(spec.rungs.len());
    for (idx, rung) in spec.rungs.iter().cloned().enumerate() {
        let (tx, rx) = tokio::sync::mpsc::channel::<VideoFrame>(FRAME_CHANNEL_CAPACITY);
        senders.push(tx);
        let sink = Arc::clone(&sink);
        let base_cfg = base_cfg.clone();
        let audio = audio.clone();
        let subtitles = subtitles.clone();
        let handle = tokio::task::spawn_blocking(move || {
            let r = encode_rung_single_file(
                idx, &rung, rx, base_cfg, backend_override, frame_rate, effective_total,
                audio.as_ref(), &subtitles, sink.as_ref(), video_delay, container,
            );
            (idx, rung, r)
        });
        handles.push(handle);
    }

    let pump_handle = {
        let rt = rt.clone();
        tokio::task::spawn_blocking(move || {
            decode_pump::run_spliced_decode_pump_blocking(clips, senders, rt)
        })
    };

    let mut outputs = Vec::new();
    for handle in handles {
        let (idx, rung, r) = handle.await.context("rung worker task panicked")?;
        match r {
            Ok(out) => outputs.push(out),
            Err(e) => report_rung_error(sink.as_ref(), idx, &rung, &e),
        }
    }
    let _ = pump_handle.await.context("decode pump panicked")?.context("decode pump failed")?;
    if outputs.is_empty() {
        bail!("all {} rung(s) failed", spec.rungs.len());
    }
    Ok(outputs)
}

/// Single-file via the multi-GPU engine: chunk each rung across GPUs, then
/// stitch the packets into one MP4 per rung (no disk round-trip — packets stay
/// in memory). Chunk length is a 2 s GOP so each chunk is an independently
/// decodable IDR sequence; the cross-vendor codec invariant keeps every chunk's
/// `av1C` contract identical so cross-GPU/-vendor stitching is bit-safe.
#[allow(clippy::too_many_arguments)]
async fn run_single_file_multigpu(
    input: Bytes,
    spec: &OutputSpec,
    header: &DemuxHeader,
    frame_rate: f64,
    total_input_frames: u64,
    audio: Option<&PreparedAudio>,
    subtitles: &[SubtitleTrack],
    gpu_pool: Arc<crate::gpu_pool::GpuPool>,
    filter_chain: Arc<codec::filter::FilterChain>,
    sink: Arc<dyn ProgressSink>,
    video_delay: (u64, u32),
) -> Result<Vec<RungOutput>> {
    let timescale = (frame_rate * 1000.0).round().max(1.0) as u32;
    let per_frame_ticks = (timescale as f64 / frame_rate.max(1.0)).round().max(1.0) as u32;
    // The GOP is the chunk grid: a chunk is a whole number of GOPs, so this is
    // the spec's `gop` when set, else two seconds.
    let keyframe_interval = spec.gop_frames(frame_rate);
    let segment_target_ticks = (keyframe_interval as u64) * (per_frame_ticks as u64);

    let (output_color_metadata, output_pixel_format) =
        spec.resolve_output(header.info.color_metadata, header.info.pixel_format);
    let params = MultiGpuParams {
        input,
        // Single-file multi-GPU is never spliced (trimmed/concat single-file
        // takes the serial path) — empty plan ⇒ the pump decodes from `input`.
        spliced_clips: Vec::new(),
        codec: spec.video_codec.codec(),
        rungs: &spec.rungs,
        header: header.clone(),
        source_color_metadata: header.info.color_metadata,
        source_pixel_format: header.info.pixel_format,
        tonemap_to_sdr: spec.tonemaps(),
        output_color_metadata,
        output_pixel_format,
        needs_downsample: needs_chroma_downsample(header.info.pixel_format),
        chroma_downsample: spec.chroma_downsample,
        filters: Arc::clone(&filter_chain),
        hooks: spec.hooks.clone(),
        frame_rate,
        gpu_pool,
        host: multigpu::HostCards::Detected,
        gpu_indices: multigpu::policy_gpu_indices(spec.encode_policy),
        decode: spec.decode_policy,
        encode: spec.encode_policy,
        // Chunk workers collect packets in memory; output_root is unused.
        output_root: std::env::temp_dir(),
        timescale,
        per_frame_ticks,
        keyframe_interval,
        segment_target_ticks,
        total_input_frames,
        // ParallelConstQp ⇒ force constant-QP chunks so stitched seams are flat.
        constant_qp: spec.chunk_seam_mode == crate::spec::ChunkSeamMode::ParallelConstQp,
        cancel: None,
        // The stitched MP4's muxer writes a late start as an edit list.
        video_delay_ticks: 0,
    };
    let rung_packets = multigpu::run_multigpu_single_file(params, Arc::clone(&sink)).await?;

    let mut outputs = Vec::new();
    for rp in rung_packets.into_iter().flatten() {
        let label = rp.label.clone();
        match mux_rung_packets(rp, spec.container, frame_rate, output_color_metadata, audio, subtitles, video_delay) {
            Ok(out) => outputs.push(out),
            Err(e) => tracing::warn!(rung = %label, error = %e, "stitching rung MP4 failed"),
        }
    }
    if outputs.is_empty() {
        bail!("multi-GPU single-file: no rung produced a stitched MP4");
    }
    Ok(outputs)
}

/// Stitch one rung's ordered AV1 packets (+ optional audio) into an MP4.
#[cfg(test)]
pub(super) fn mux_rung_packets_to_mp4(
    rp: RungPackets,
    frame_rate: f64,
    color_metadata: ColorMetadata,
    audio: Option<&PreparedAudio>,
    subtitles: &[SubtitleTrack],
    video_delay: (u64, u32),
) -> Result<RungOutput> {
    mux_rung_packets(rp, Container::Mp4, frame_rate, color_metadata, audio, subtitles, video_delay)
}

/// Stitch one rung's ordered packets (+ optional audio) into the file
/// `container` names: an MP4 or a QuickTime movie (the chunked path runs
/// the web set only, which WebM does not carry).
pub(super) fn mux_rung_packets(
    rp: RungPackets,
    container: Container,
    frame_rate: f64,
    color_metadata: ColorMetadata,
    audio: Option<&PreparedAudio>,
    subtitles: &[SubtitleTrack],
    video_delay: (u64, u32),
) -> Result<RungOutput> {
    // Multi-GPU stitch: chunks come from independent encoders (possibly
    // different vendors). Where every chunk wrote the same parameter sets —
    // sessions of one encoder, one configuration — they go out of band under
    // `avc1`/`hvc1`, the sample entry every player takes (Safari's `<video>`
    // refuses `avc3`). Where they differ, each chunk keeps its own in band,
    // under `avc3`/`hev1`. AV1 stores OBUs verbatim and has neither.
    let nal_codec = match rp.codec {
        VideoCodec::H264 => Some(container::nal_mux::NalMuxCodec::H264),
        VideoCodec::H265 => Some(container::nal_mux::NalMuxCodec::H265),
        _ => None,
    };
    let fixed = nal_codec.is_none_or(|c| {
        container::nal_mux::parameter_sets_fixed(c, rp.packets.iter().map(|p| &p.data[..]))
    });
    if !fixed {
        tracing::info!(
            rung = %rp.label,
            "the stitched chunks' parameter sets differ; keeping them in band (avc3/hev1)"
        );
    }
    let mut muxer = FileMuxer::new(container, rp.width, rp.height, frame_rate, rp.codec, !fixed)?;
    muxer.set_color_metadata(color_metadata);
    muxer.set_video_delay(video_delay.0, video_delay.1);
    if let Some(a) = audio {
        muxer.add_audio(a, &rp.label)?;
    }
    muxer.attach_subtitles(subtitles, &rp.label);
    let frames = rp.packets.len() as u64;
    for pkt in rp.packets {
        muxer.add_packet(pkt).context("add_packet")?;
    }
    let bytes = muxer.finalize()?;
    let nbytes = bytes.len() as u64;
    Ok(RungOutput {
        label: rp.label,
        width: rp.width,
        height: rp.height,
        frames,
        bytes: nbytes,
        artifact: RungArtifact::File(bytes),
    })
}

#[allow(clippy::too_many_arguments)]
pub(super) fn encode_rung_single_file(
    rung_index: usize,
    rung: &Rung,
    mut rx: tokio::sync::mpsc::Receiver<VideoFrame>,
    mut cfg: EncoderConfig,
    backend: Option<EncoderBackend>,
    frame_rate: f64,
    frames_total: Option<u64>,
    audio: Option<&PreparedAudio>,
    subtitles: &[SubtitleTrack],
    sink: &dyn ProgressSink,
    video_delay: (u64, u32),
    container: Container,
) -> Result<RungOutput> {
    cfg.width = rung.width;
    cfg.height = rung.height;
    rung.quality.apply(&mut cfg, frame_rate);

    let out_color = cfg.color_metadata;
    let out_codec = cfg.codec;
    let mut encoder = encode::select_encoder(cfg, backend)
        .with_context(|| format!("creating encoder for rung {}", rung.label))?;
    let mut muxer = FileMuxer::new(container, rung.width, rung.height, frame_rate, out_codec, false)?;
    muxer.set_color_metadata(out_color);
    muxer.set_video_delay(video_delay.0, video_delay.1);

    if let Some(a) = audio {
        muxer.add_audio(a, &rung.label)?;
    }

    muxer.attach_subtitles(subtitles, &rung.label);

    let mut frames: u64 = 0;
    // Running total of encoded payload so the CLI can show size to date and
    // project a finished size, matching what the chunked path reports.
    let mut bytes_encoded: u64 = 0;
    report(sink, rung_index, rung, RungStatus::Running, 0, frames_total, 0, 0);
    while let Some(frame) = rx.blocking_recv() {
        let scaled = rung.scale(&frame).context("scaling to the rung")?;
        encoder.send_frame(&scaled).context("send_frame")?;
        while let Some(pkt) = encoder.receive_packet().context("receive_packet")? {
            bytes_encoded += pkt.data.len() as u64;
            muxer.add_packet(pkt).context("add_packet")?;
        }
        frames += 1;
        if frames.is_multiple_of(30) {
            report(sink, rung_index, rung, RungStatus::Running, frames, frames_total, 0, bytes_encoded);
        }
    }
    encoder.flush().context("encoder flush")?;
    while let Some(pkt) = encoder.receive_packet().context("receive_packet drain")? {
        muxer.add_packet(pkt).context("add_packet drain")?;
    }
    report(sink, rung_index, rung, RungStatus::Finalizing, frames, frames_total, 0, bytes_encoded);
    let bytes = muxer.finalize()?;
    let nbytes = bytes.len() as u64;
    report(sink, rung_index, rung, RungStatus::Completed, frames, frames_total, 0, nbytes);

    Ok(RungOutput {
        label: rung.label.clone(),
        width: rung.width,
        height: rung.height,
        frames,
        bytes: nbytes,
        artifact: RungArtifact::File(bytes),
    })
}

// ---------------------------------------------------------------------------
// Misc helpers local to this file
// ---------------------------------------------------------------------------

/// The thread budget each of `rungs` concurrent serial encoders gets:
/// the machine divided by the rung count, never below one.
fn serial_threads_per_rung(rungs: usize) -> usize {
    let parallelism = std::thread::available_parallelism().map(|n| n.get()).unwrap_or(1);
    divide_threads(parallelism, rungs)
}

/// `parallelism / rungs`, clamped to at least one thread per rung.
fn divide_threads(parallelism: usize, rungs: usize) -> usize {
    (parallelism / rungs.max(1)).max(1)
}

pub(super) fn encoder_backend_override() -> Option<EncoderBackend> {
    std::env::var("TRANSCODE_ENCODER_BACKEND")
        .ok()
        .and_then(|s| match s.to_ascii_lowercase().as_str() {
            "nvenc" => Some(EncoderBackend::Nvenc),
            "amf" => Some(EncoderBackend::Amf),
            "qsv" => Some(EncoderBackend::Qsv),
            "h26x" => Some(EncoderBackend::H26x),
            "av1" | "rav1e" => Some(EncoderBackend::Av1),
            other => crate::spec::encoder_backend_from_name(other),
        })
}

#[allow(clippy::too_many_arguments)]
fn report(
    sink: &dyn ProgressSink,
    rung_index: usize,
    rung: &Rung,
    status: RungStatus,
    frames_done: u64,
    frames_total: Option<u64>,
    segments: u32,
    bytes_out: u64,
) {
    let percent = match status {
        RungStatus::Completed => 100.0,
        RungStatus::Pending => 0.0,
        _ => match frames_total {
            Some(total) if total > 0 => ((frames_done as f32 / total as f32) * 100.0).min(99.0),
            _ => {
                if frames_done == 0 { 1.0 } else { 50.0 }
            }
        },
    };
    sink.on_rung(RungProgress {
        rung_index,
        label: rung.label.clone(),
        width: rung.width,
        height: rung.height,
        status,
        percent,
        frames_done,
        frames_total,
        segments_written: segments,
        bytes_out,
        message: None,
    });
}

#[cfg(test)]
mod thread_split_tests {
    use super::divide_threads;

    /// N rungs at once must not each take the whole machine.
    #[test]
    fn rungs_share_the_machine() {
        assert_eq!(divide_threads(32, 3), 10);
        assert_eq!(divide_threads(32, 1), 32);
        assert_eq!(divide_threads(32, 5), 6);
        // More rungs than cores: one thread each, never zero (which the
        // encoders read as "every core").
        assert_eq!(divide_threads(4, 8), 1);
        assert_eq!(divide_threads(4, 0), 4);
        for (p, r) in [(32usize, 3usize), (8, 3), (2, 7), (1, 1)] {
            let t = divide_threads(p, r);
            assert!(t >= 1);
            assert!(t * r <= p.max(r), "{p}/{r} oversubscribed: {t}");
        }
    }
}
