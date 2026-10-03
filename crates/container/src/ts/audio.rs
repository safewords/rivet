//! AAC-ADTS, AC-3, and E-AC-3 audio extraction from MPEG-TS PES streams.
//!
//! # AAC-ADTS (Squad-27)
//!
//! The MPEG-TS audio path stores AAC as a stream of ADTS frames inside PES
//! packets — same PES framing as the video path, but the elementary stream
//! payload is ADTS, not Annex-B. The downstream mux (Squad-18) wants raw
//! AAC access units (no ADTS header) plus a synthesized AudioSpecificConfig
//! (ASC) — both come from the first ADTS header.
//!
//! References:
//! - ADTS frame layout: ISO/IEC 13818-7 §6.2 (the "_adts_frame()" syntax
//!   table — 7-byte fixed header without CRC, 9-byte with CRC).
//! - ASC layout: ISO/IEC 14496-3 §1.6.2 (`AudioSpecificConfig` →
//!   `GetAudioObjectType` + `samplingFrequencyIndex` + `channelConfiguration`
//!   + `GASpecificConfig` for AOT 1..7).
//!
//! # AC-3 / E-AC-3 (Squad-37)
//!
//! PES payload for an AC-3 / E-AC-3 audio PID is a stream of raw
//! syncframes — 0x0B77 sync word at the start of each frame, followed by
//! the BSI fields whose layout `crate::ac3_sync` already parses for
//! MP4 / MKV passthrough. Squad-26 settled the codec_private wire
//! format: a 3-byte `dac3` body for AC-3, a 5-byte `dec3` body for
//! vanilla single-substream E-AC-3.
//!
//! The MP4 mux contract (Squad-26) is: pass the raw AC-3 / E-AC-3
//! frames through verbatim as samples; populate `codec_private` with the
//! dac3/dec3 body derived from the first frame; `asc` stays empty for
//! these codecs. We do NOT re-frame, decode, or strip anything — the
//! frames are length-self-describing via the syncframe info, and the
//! muxer / downstream demuxer round-trip in Squad-26 already handles
//! that on the MP4 side.

use anyhow::{Context, Result, bail};

use crate::aac_asc::{BitReader, ProgramConfig, parse_pce, synthesize_asc_with_pce};
use crate::ac3_sync::{
    self, Eac3SyncInfo, SyncInfo, ac3_bit_rate_kbps, channel_count, eac3_sample_rate_hz,
    eac3_samples_per_frame,
};
use crate::demux::AudioTrack;
use crate::edit::rescale_round;
use crate::mux::dac3_body_from_sync;

use super::clock::{PTS_HZ, PTS_MODULUS};
use super::{AudioCodecKind, AudioStreamInfo, TS_PACKET, TS_SYNC};

/// An audio track read from a transport stream, with where its first frame
/// sits on the program clock.
#[derive(Debug)]
pub(super) struct TsAudio {
    pub(super) track: AudioTrack,
    /// The first frame's PTS, as the stream has it (33-bit); `None` when no
    /// PES packet ties a PTS to a frame the track kept.
    pub(super) first_pts: Option<u64>,
    /// Every PES packet of the track: where its bytes start in the elementary
    /// stream, its PTS as the stream has it, and the TS packet it starts in.
    pub(super) pes: Vec<AudioPes>,
    /// Where each of the track's frames starts in the elementary stream.
    pub(super) frame_starts: Vec<usize>,
}

/// One audio PES packet: its elementary-stream offset, PTS, and TS packet.
pub(super) type AudioPes = (usize, Option<u64>, usize);

// ---------------------------------------------------------------------------
// AAC-ADTS helpers
// ---------------------------------------------------------------------------

// Sampling frequency table (ISO/IEC 14496-3 §1.6.3.4 Table 1.16):
const AAC_SAMPLE_RATES: [u32; 13] = [
    96000, 88200, 64000, 48000, 44100, 32000, 24000, 22050, 16000, 12000, 11025, 8000, 7350,
];

/// Parsed view of a single ADTS frame header (ISO/IEC 13818-7 §6.2).
/// Only the fields we need for ASC synthesis + frame slicing — buffer
/// fullness / number_of_raw_data_blocks are not exposed.
#[derive(Debug, Clone, Copy, PartialEq, Eq)]
pub(super) struct AdtsHeader {
    /// ADTS profile (2 bits): AAC ObjectType - 1.
    /// `0`=Main, `1`=LC, `2`=SSR, `3`=LTP. Maps to ASC AOT via `+1`.
    pub(super) profile: u8,
    /// Sampling frequency index (4 bits, 0..=12 valid; 15 = explicit).
    /// `decode_sample_rate_index` resolves to Hz.
    pub(super) sampling_frequency_index: u8,
    /// `channel_configuration` (3 bits): Table 1.19 (1 = mono, 2 = stereo,
    /// 6 = 5.1, 7 = 7.1 — eight channels). 0 = "layout defined in the PCE"
    /// at the head of the raw data block; `extract_ts_aac_audio` reads it.
    pub(super) channel_configuration: u8,
    /// Whole frame length in bytes including header + (optional CRC) +
    /// AAC payload.
    pub(super) frame_length: usize,
    /// Length of the ADTS header itself: 7 bytes if `protection_absent`
    /// (no CRC), 9 bytes otherwise.
    pub(super) header_len: usize,
}

/// Parse an ADTS frame header at `buf[0..]`. Returns the parsed header on
/// success. Does NOT validate the CRC even when present — the demux path
/// trusts the upstream PMT routing to point us at AAC bytes; a corrupt
/// stream surfaces as a sync-loss frame downstream.
pub(super) fn parse_adts_header(buf: &[u8]) -> Option<AdtsHeader> {
    if buf.len() < 7 {
        return None;
    }
    // Sync word: 12 bits = 0xFFF. Bytes 0..1 = `1111_1111  1111_xxxx`.
    if buf[0] != 0xFF || (buf[1] & 0xF0) != 0xF0 {
        return None;
    }
    let protection_absent = (buf[1] & 0x01) != 0;
    let header_len = if protection_absent { 7 } else { 9 };
    if buf.len() < header_len {
        return None;
    }
    let profile = (buf[2] >> 6) & 0x03;
    let sampling_frequency_index = (buf[2] >> 2) & 0x0F;
    // channel_configuration straddles bytes 2..3:
    //   bit 0 of byte 2 (low bit after profile/sr_idx/private) = ch_cfg high bit
    //   bits 7..6 of byte 3 (top two bits)                     = ch_cfg low 2 bits
    let channel_configuration = ((buf[2] & 0x01) << 2) | ((buf[3] >> 6) & 0x03);
    // frame_length is 13 bits across bytes 3..4..5:
    //   bits 1..0 of byte 3 = frame_length[12..11]
    //   bits 7..0 of byte 4 = frame_length[10..3]
    //   bits 7..5 of byte 5 = frame_length[2..0]
    let frame_length =
        (((buf[3] & 0x03) as usize) << 11) | ((buf[4] as usize) << 3) | ((buf[5] >> 5) as usize);
    if frame_length < header_len {
        return None;
    }
    Some(AdtsHeader {
        profile,
        sampling_frequency_index,
        channel_configuration,
        frame_length,
        header_len,
    })
}

/// Resolve an ADTS sampling_frequency_index to Hz. Only indices 0..=12 are
/// recognised; 13/14 are reserved and 15 ("escape") would carry an
/// explicit 24-bit rate after the header, which we don't accept (no
/// real-world AAC ADTS file uses index 15 — the escape form is for
/// AAC-in-LATM, not ADTS).
pub(super) fn decode_sample_rate_index(idx: u8) -> Option<u32> {
    AAC_SAMPLE_RATES.get(idx as usize).copied()
}

/// Synthesize a 2-byte AudioSpecificConfig from an ADTS header per
/// ISO/IEC 14496-3 §1.6.2:
/// - 5 bits: audioObjectType = ADTS profile + 1
///   (so ADTS profile=1 LC → ASC AOT=2 LC; ADTS profile=4 HE-AAC parent
///   AOT=5 SBR → also AOT=5 here, though real HE-AAC ASC also signals
///   SBR explicitly via extension AOT — we don't try to do that, the
///   mux validation rejects HE-AAC anyway).
/// - 4 bits: samplingFrequencyIndex (copy from ADTS verbatim)
/// - 4 bits: channelConfiguration (copy from ADTS verbatim)
/// - 3 bits: GASpecificConfig padding (frameLengthFlag=0,
///   dependsOnCoreCoder=0, extensionFlag=0)
///
/// Total: 16 bits = 2 bytes.
///
/// Example: ADTS profile=1 (LC), sr_idx=3 (48k), ch_cfg=2 (stereo) →
/// ASC bytes `0x11 0x90`.
pub(super) fn synthesize_asc(adts: &AdtsHeader) -> [u8; 2] {
    let aot = adts.profile + 1; // ADTS profile (AOT-1) → ASC AOT
    let sr_idx = adts.sampling_frequency_index;
    let ch_cfg = adts.channel_configuration;
    // Bit layout (MSB first, 16 bits):
    //   AOT(5) | sr_idx(4) | ch_cfg(4) | GA padding(3)
    // Pack into a u16 then split to BE bytes.
    let mut bits: u16 = 0;
    bits |= ((aot as u16) & 0x1F) << 11;
    bits |= ((sr_idx as u16) & 0x0F) << 7;
    bits |= ((ch_cfg as u16) & 0x0F) << 3;
    // GA padding bits already 0.
    bits.to_be_bytes()
}

/// Channel count for an ADTS `channel_configuration` 1..=7 (Table 1.19:
/// 7 is 7.1, eight channels; the rest equal their index).
fn channels_for_config(cfg: u8) -> u16 {
    if cfg == 7 { 8 } else { cfg as u16 }
}

/// The PCE at the head of a raw data block: `id_syn_ele` (3 bits) must be
/// ID_PCE (5), then `program_config_element()`.
fn pce_from_raw_block(block: &[u8]) -> Option<ProgramConfig> {
    let mut br = BitReader::new(block);
    if br.bits(3)? != 5 {
        return None;
    }
    parse_pce(&mut br)
}

/// Find the next ADTS sync word at or after `from` in `es`. Returns the
/// offset of the sync byte (0xFF) or `None`.
fn find_adts_sync(es: &[u8], from: usize) -> Option<usize> {
    let mut i = from;
    while i + 1 < es.len() {
        if es[i] == 0xFF && (es[i + 1] & 0xF0) == 0xF0 {
            return Some(i);
        }
        i += 1;
    }
    None
}

/// Reassemble all PES packets on `audio_pid` and split the resulting
/// elementary stream into ADTS frames. Returns one `Vec<u8>` per frame
/// (raw access unit — ADTS header stripped) and a parallel duration list
/// in `sample_rate` ticks (always 1024 per AAC-LC frame).
///
/// The first valid ADTS header drives ASC synthesis; subsequent frames
/// must carry the same sampling_frequency_index and channel_configuration
/// — a switch mid-stream would invalidate the ASC and the mux can't
/// tolerate that. We currently bail out of audio extraction if the
/// stream switches; downstream falls back to video-only.
fn extract_ts_aac_audio(
    data: &[u8],
    packets: usize,
    packet_stride: usize,
    prefix_len: usize,
    audio_pid: u16,
) -> Result<Option<TsAudio>> {
    // Reassemble all PES packets on `audio_pid` into one elementary
    // stream — shared with the AC-3 / E-AC-3 paths (Squad-37). ADTS
    // sync words let us split into frames after the fact.
    let (es, pes) = reassemble_audio_pes(data, packets, packet_stride, prefix_len, audio_pid);

    if es.is_empty() {
        return Ok(None);
    }

    // Step 2: scan for the first valid ADTS sync, derive ASC.
    let mut cursor = match find_adts_sync(&es, 0) {
        Some(idx) => idx,
        None => return Ok(None),
    };
    let first = parse_adts_header(&es[cursor..]).context("TS: first ADTS frame failed to parse")?;
    let sample_rate = decode_sample_rate_index(first.sampling_frequency_index)
        .context("TS: AAC sampling_frequency_index out of range")?;
    // channel_configuration 0 means the layout is described by a PCE at the
    // head of the (first) raw data block — ffmpeg writes 7.1 that way, and
    // anything with `-aac_pce 1`. Read it: the count comes from the PCE and
    // the ASC has to carry it (re-serialised, since its byte alignment
    // differs between the raw block and the ASC). Frames stay verbatim —
    // the in-band PCE is legal in MP4 and matches the ASC's.
    let (channels, asc) = if first.channel_configuration == 0 {
        let pce = pce_from_raw_block(&es[cursor + first.header_len..])
            .context("TS: AAC channel_configuration=0 but the first raw data block does not start with a PCE")?;
        let channels = pce.channel_count();
        if channels == 0 {
            bail!("TS: AAC PCE describes no output channels");
        }
        tracing::info!(
            channels,
            "TS: AAC channel layout taken from the in-band PCE (channel_configuration=0)"
        );
        (
            channels,
            synthesize_asc_with_pce(first.profile + 1, first.sampling_frequency_index, &pce),
        )
    } else {
        (
            channels_for_config(first.channel_configuration),
            synthesize_asc(&first).to_vec(),
        )
    };

    // Step 3: walk frames, strip headers, accumulate samples + durations.
    // Each AAC-LC frame is exactly 1024 samples per channel — that's the
    // duration in `sample_rate` ticks (timescale = sample_rate).
    let mut samples: Vec<Vec<u8>> = Vec::new();
    let mut durations: Vec<u32> = Vec::new();
    let mut starts: Vec<usize> = Vec::new();
    while cursor < es.len() {
        // Resync if we've drifted off a frame boundary (rare in practice
        // but possible on packet loss or if a PES header extension we
        // don't recognise pushed garbage into the ES).
        let Some(found) = find_adts_sync(&es, cursor) else {
            break;
        };
        cursor = found;
        let Some(hdr) = parse_adts_header(&es[cursor..]) else {
            break;
        };
        if hdr.sampling_frequency_index != first.sampling_frequency_index
            || hdr.channel_configuration != first.channel_configuration
        {
            tracing::warn!(
                "TS: AAC ADTS stream switched sr_idx/ch_cfg mid-stream; truncating audio at frame {}",
                samples.len()
            );
            break;
        }
        let end = cursor + hdr.frame_length;
        if end > es.len() {
            break;
        }
        let payload_start = cursor + hdr.header_len;
        if payload_start > end {
            break;
        }
        samples.push(es[payload_start..end].to_vec());
        durations.push(1024);
        starts.push(cursor);
        cursor = end;
    }

    if samples.is_empty() {
        return Ok(None);
    }

    Ok(Some(TsAudio {
        first_pts: first_frame_pts(&pes, &starts, &durations, sample_rate),
        pes,
        frame_starts: starts,
        track: AudioTrack {
            codec: "aac".into(),
            samples,
            sample_rate,
            channels,
            asc,
            codec_private: Vec::new(),
            timescale: sample_rate,
            durations,
        },
    }))
}

// ---------------------------------------------------------------------------
// AC-3 / E-AC-3 helpers
// ---------------------------------------------------------------------------

/// Find the next 0x0B77 AC-3 / E-AC-3 sync word at or after `from`.
fn find_ac3_sync(es: &[u8], from: usize) -> Option<usize> {
    let mut i = from;
    while i + 1 < es.len() {
        if es[i] == 0x0B && es[i + 1] == 0x77 {
            return Some(i);
        }
        i += 1;
    }
    None
}

/// Compute the byte length of one AC-3 syncframe given its bit-rate
/// code and fscod. ETSI TS 102 366 §F Table F.7 gives the wire-byte
/// count per (bit_rate_code, fscod) pair; the closed form is:
///   for fscod=0 (48k):  frame_size_bytes = 2 * frame_size_words[brc]
///                       where frame_size_words = bit_rate_kbps * 32 / 48 / 2
///                       reduces to: bytes = bit_rate_kbps * 4 / 3
/// For 44.1k and 32k there's a per-(brc,fscod) padding offset table; we
/// derive it from the algebraic identity bytes = bit_rate_kbps * 1000 /
/// (sample_rate / samples_per_frame * 8). AC-3 has a fixed 1536 samples
/// per frame, so:
///   bytes = bit_rate_kbps * 1000 * 1536 / sample_rate / 8
///         = bit_rate_kbps * 192000 / sample_rate
/// 44.1k frames are not byte-exact this way (frame size oscillates
/// between two adjacent values to track the average rate); the bsi
/// `frmsizecod` low bit indicates which of the two values applies, so
/// we honour it and add 2 bytes when set. For 48k and 32k the low bit
/// is irrelevant (rates divide evenly).
fn ac3_frame_size(brc: u8, fscod: u8, frmsizecod_low_bit: u8) -> Option<usize> {
    let kbps = ac3_bit_rate_kbps(brc) as usize;
    if kbps == 0 {
        return None;
    }
    let sr = ac3_sync::ac3_sample_rate_hz(fscod) as usize;
    if sr == 0 {
        return None;
    }
    let base = (kbps * 1000 * 1536) / (sr * 8);
    // 44.1k oscillation: one of two frame sizes per syncframe (the low
    // bit of frmsizecod selects). At 48k / 32k both sides match the
    // algebraic value, so the bit is harmless.
    let extra = if fscod == 1 && frmsizecod_low_bit != 0 {
        2
    } else {
        0
    };
    Some(base + extra)
}

/// Compute the byte length of one E-AC-3 syncframe — the BSI directly
/// carries `frmsiz` (frame_size_words - 1), so frame_size_bytes is
/// (frmsiz + 1) * 2.
fn eac3_frame_size(frmsiz: u16) -> usize {
    ((frmsiz as usize) + 1) * 2
}

/// Extract AC-3 frames from PES packets on `audio_pid`. Returns an
/// `AudioTrack` with `codec = "ac3"`, `codec_private = dac3 body`, and
/// one sample per AC-3 syncframe (raw frame bytes verbatim).
///
/// The first valid syncframe drives `dac3` / sample_rate / channel
/// derivation; subsequent frames are emitted as samples without
/// re-validating their BSI (a corrupt mid-stream sync would surface as
/// a downstream decoder error, the same way our AAC path handles it).
fn extract_ts_ac3_audio(
    data: &[u8],
    packets: usize,
    packet_stride: usize,
    prefix_len: usize,
    audio_pid: u16,
) -> Result<Option<TsAudio>> {
    let (es, pes) = reassemble_audio_pes(data, packets, packet_stride, prefix_len, audio_pid);
    let Some((track, starts)) = ac3_from_es(&es)? else {
        return Ok(None);
    };
    Ok(Some(TsAudio {
        first_pts: first_frame_pts(&pes, &starts, &track.durations, track.sample_rate),
        pes,
        frame_starts: starts,
        track,
    }))
}

/// An AC-3 track from an elementary stream: one sample per syncframe, re-synced
/// on 0x0B77 and sliced by the frame size its header gives, with the `dac3`
/// from the first frame's BSI; beside it, where each kept frame starts.
/// `None` for a stream with no frame. Shared by the transport-stream and
/// program-stream demuxers.
pub(crate) fn ac3_from_es(es: &[u8]) -> Result<Option<(AudioTrack, Vec<usize>)>> {
    if es.is_empty() {
        return Ok(None);
    }
    let mut cursor = match find_ac3_sync(es, 0) {
        Some(idx) => idx,
        None => return Ok(None),
    };
    // Parse the first frame's BSI to derive dac3 + sample_rate + channels.
    let first = match ac3_sync::parse_sync_info(&es[cursor..])
        .context("TS: first AC-3 frame failed to parse sync header")?
    {
        SyncInfo::Ac3(s) => s,
        SyncInfo::Eac3(_) => bail!("TS: AC-3 PMT entry but bitstream is E-AC-3 (bsid=16)"),
    };
    let sample_rate = ac3_sync::ac3_sample_rate_hz(first.fscod);
    if sample_rate == 0 {
        bail!("TS: AC-3 fscod={} reserved", first.fscod);
    }
    let channels = channel_count(first.acmod, first.lfeon);
    let dac3 = dac3_body_from_sync(&first).to_vec();

    // Walk frames: re-sync on 0x0B77, slice by computed frame size, push
    // the slice as a sample. AC-3 emits 1536 samples per frame.
    let mut samples: Vec<Vec<u8>> = Vec::new();
    let mut durations: Vec<u32> = Vec::new();
    let mut starts: Vec<usize> = Vec::new();
    while cursor < es.len() {
        let Some(found) = find_ac3_sync(es, cursor) else {
            break;
        };
        cursor = found;
        // Re-read the per-frame frmsizecod low bit so the 44.1k
        // oscillation lands on the right boundary.
        if cursor + 5 > es.len() {
            break;
        }
        let frmsizecod = es[cursor + 4] & 0x3F;
        let bit_rate_code = frmsizecod >> 1;
        let low_bit = frmsizecod & 0x01;
        let fscod = (es[cursor + 4] >> 6) & 0x03;
        let Some(size) = ac3_frame_size(bit_rate_code, fscod, low_bit) else {
            break;
        };
        let end = cursor + size;
        if end > es.len() {
            break;
        }
        samples.push(es[cursor..end].to_vec());
        durations.push(1536);
        starts.push(cursor);
        cursor = end;
    }
    if samples.is_empty() {
        return Ok(None);
    }
    Ok(Some((
        AudioTrack {
            codec: "ac3".into(),
            samples,
            sample_rate,
            channels,
            asc: Vec::new(),
            codec_private: dac3,
            timescale: sample_rate,
            durations,
        },
        starts,
    )))
}

/// Extract E-AC-3 frames from PES packets on `audio_pid`. Returns an
/// `AudioTrack` with `codec = "eac3"`, `codec_private = dec3 body`, and
/// one sample per E-AC-3 syncframe (raw frame bytes verbatim).
///
/// `dec3.data_rate` is computed from the first frame: frame_size_bytes /
/// samples_per_frame * sample_rate * 8 / 1000 (kbps, ETSI TS 102 366 F.6.2.2).
fn extract_ts_eac3_audio(
    data: &[u8],
    packets: usize,
    packet_stride: usize,
    prefix_len: usize,
    audio_pid: u16,
) -> Result<Option<TsAudio>> {
    let (es, pes) = reassemble_audio_pes(data, packets, packet_stride, prefix_len, audio_pid);
    if es.is_empty() {
        return Ok(None);
    }
    let mut cursor = match find_ac3_sync(&es, 0) {
        Some(idx) => idx,
        None => return Ok(None),
    };
    let first: Eac3SyncInfo = match ac3_sync::parse_sync_info(&es[cursor..])
        .context("TS: first E-AC-3 frame failed to parse sync header")?
    {
        SyncInfo::Eac3(s) => s,
        SyncInfo::Ac3(_) => bail!("TS: E-AC-3 PMT entry but bitstream is AC-3 (bsid<=10)"),
    };
    let sample_rate = eac3_sample_rate_hz(first.fscod, first.fscod2);
    if sample_rate == 0 {
        bail!(
            "TS: E-AC-3 reserved sample rate (fscod={}, fscod2={})",
            first.fscod,
            first.fscod2
        );
    }
    let spf = eac3_samples_per_frame(first.numblkscod) as u64;

    let mut samples: Vec<Vec<u8>> = Vec::new();
    let mut durations: Vec<u32> = Vec::new();
    let mut starts: Vec<usize> = Vec::new();
    while cursor < es.len() {
        let Some(found) = find_ac3_sync(&es, cursor) else {
            break;
        };
        cursor = found;
        if cursor + 5 > es.len() {
            break;
        }
        // Re-read frmsiz from this frame's BSI: bytes 2..4 carry
        // strmtyp(2) + substreamid(3) + frmsiz(11). frmsiz = bits 5..15
        // of the BE u16 starting at byte 2.
        let raw = u16::from_be_bytes([es[cursor + 2], es[cursor + 3]]);
        let frmsiz = raw & 0x07FF;
        let size = eac3_frame_size(frmsiz);
        let end = cursor + size;
        if end > es.len() {
            break;
        }
        // A dependent substream (strmtyp 1: 7.1's back surrounds) belongs
        // to the access unit of the independent syncframe before it: one
        // sample, one duration, as an MP4 sample holds it.
        let dependent = raw >> 14 == 1;
        match samples.last_mut() {
            Some(last) if dependent => last.extend_from_slice(&es[cursor..end]),
            _ => {
                samples.push(es[cursor..end].to_vec());
                durations.push(spf as u32);
                starts.push(cursor);
            }
        }
        cursor = end;
    }
    if samples.is_empty() {
        return Ok(None);
    }
    // The dec3 and the channel count from the first access unit, its
    // dependent substreams included.
    let Some((dec3, _, channels)) = crate::mux::eac3_config_from_access_unit(&samples[0]) else {
        bail!("TS: the first E-AC-3 access unit does not parse");
    };
    Ok(Some(TsAudio {
        first_pts: first_frame_pts(&pes, &starts, &durations, sample_rate),
        pes,
        frame_starts: starts,
        track: AudioTrack {
            codec: "eac3".into(),
            samples,
            sample_rate,
            channels,
            asc: Vec::new(),
            codec_private: dec3,
            timescale: sample_rate,
            durations,
        },
    }))
}

// ---------------------------------------------------------------------------
// Shared PES reassembly for audio PIDs
// ---------------------------------------------------------------------------

/// Reassemble all PES payloads on `audio_pid` into one elementary stream
/// `Vec<u8>`. Shared between the AAC, AC-3 and E-AC-3 audio extractors —
/// each codec slices the resulting buffer into frames using its own
/// sync-word + frame-size logic. Beside it, every PES packet's start in that
/// buffer and the PTS its header carried ([`first_frame_pts`]).
fn reassemble_audio_pes(
    data: &[u8],
    packets: usize,
    packet_stride: usize,
    prefix_len: usize,
    audio_pid: u16,
) -> (Vec<u8>, Vec<AudioPes>) {
    let mut es: Vec<u8> = Vec::new();
    let mut pes: Vec<AudioPes> = Vec::new();
    let mut have_first_start = false;
    for i in 0..packets {
        let start = i * packet_stride + prefix_len;
        let pkt = &data[start..start + TS_PACKET];
        if pkt[0] != TS_SYNC {
            continue;
        }
        let pid = (((pkt[1] & 0x1F) as u16) << 8) | pkt[2] as u16;
        if pid != audio_pid {
            continue;
        }
        let pusi = pkt[1] & 0x40 != 0;
        let scramble = (pkt[3] >> 6) & 0x03;
        if scramble != 0 {
            continue;
        }
        let adaptation = (pkt[3] >> 4) & 0x03;
        let has_payload = adaptation & 0x01 != 0;
        let has_adaptation = adaptation & 0x02 != 0;
        if !has_payload {
            continue;
        }

        let mut offset = 4usize;
        if has_adaptation {
            if offset >= TS_PACKET {
                continue;
            }
            let adap_len = pkt[offset] as usize;
            offset += 1 + adap_len;
            if offset > TS_PACKET {
                continue;
            }
        }
        if offset >= TS_PACKET {
            continue;
        }
        let payload = &pkt[offset..];

        if pusi {
            let Some((es_start, pts)) = parse_pes_header_audio(payload) else {
                have_first_start = false;
                continue;
            };
            have_first_start = true;
            pes.push((es.len(), pts, i));
            if es_start < payload.len() {
                es.extend_from_slice(&payload[es_start..]);
            }
        } else if have_first_start {
            es.extend_from_slice(payload);
        }
    }
    (es, pes)
}

/// The PTS of a track's first frame, from the PES packets (`pes`: where each
/// starts in the elementary stream, and its PTS) and the frames the walk kept
/// (`frame_starts` in the same buffer, `durations` in `sample_rate` ticks).
///
/// A PES packet's PTS is that of the first access unit commencing in it
/// (ISO/IEC 13818-1 §2.4.3.7). So the first PES packet with a PTS in which a
/// kept frame commences places that frame, and the first frame lies the frames
/// before it earlier — which is also right when the stream opens with a packet
/// that carries no PTS, or with the tail of a frame cut off before it. Modulo
/// 2^33, as the stream has it.
fn first_frame_pts(
    pes: &[AudioPes],
    frame_starts: &[usize],
    durations: &[u32],
    sample_rate: u32,
) -> Option<u64> {
    for (i, &(offset, pts, _)) in pes.iter().enumerate() {
        let Some(pts) = pts else { continue };
        let end = pes.get(i + 1).map_or(usize::MAX, |&(next, _, _)| next);
        let k = frame_starts.partition_point(|&s| s < offset);
        if frame_starts.get(k).is_some_and(|&s| s < end) {
            let before: u64 = durations[..k].iter().map(|&d| u64::from(d)).sum();
            let back = rescale_round(before, PTS_HZ, sample_rate) as i64;
            return Some((pts as i64 - back).rem_euclid(PTS_MODULUS) as u64);
        }
    }
    None
}

/// Parse a PES header for audio (stream_id 0xC0..=0xDF). Same shape as
/// `parse_pes_header` for video but accepts the audio stream_id range.
/// Returns `(es_start, pts)`.
fn parse_pes_header_audio(payload: &[u8]) -> Option<(usize, Option<u64>)> {
    if payload.len() < 9 {
        return None;
    }
    if payload[0] != 0 || payload[1] != 0 || payload[2] != 1 {
        return None;
    }
    let stream_id = payload[3];
    // Audio streams are 0xC0..=0xDF per ISO/IEC 13818-1 §2.4.3.7; AC-3 and
    // E-AC-3 ride private_stream_1 (0xBD) per ATSC A/53 Part 3 §6.5 and
    // ETSI TS 101 154 §6.1, so that id is accepted on the audio PID too, as
    // is extended_stream_id (0xFD), which Blu-ray and GStreamer's mpegtsmux
    // give AC-3; its header has the same optional-fields layout.
    if !(0xC0..=0xDF).contains(&stream_id) && stream_id != 0xBD && stream_id != 0xFD {
        return None;
    }
    let flags = payload[7];
    let pts_dts_flags = (flags >> 6) & 0x03;
    let header_data_len = payload[8] as usize;
    let es_start = 9 + header_data_len;
    if es_start > payload.len() {
        return None;
    }
    let pts = if pts_dts_flags == 0b10 || pts_dts_flags == 0b11 {
        if payload.len() < 14 {
            return None;
        }
        let p0 = ((payload[9] >> 1) & 0x07) as u64;
        let p1 = (((payload[10] as u64) << 7) | ((payload[11] as u64) >> 1)) & 0x7FFF;
        let p2 = (((payload[12] as u64) << 7) | ((payload[13] as u64) >> 1)) & 0x7FFF;
        Some((p0 << 30) | (p1 << 15) | p2)
    } else {
        None
    };
    Some((es_start, pts))
}

// ---------------------------------------------------------------------------
// Dispatch
// ---------------------------------------------------------------------------

/// Dispatch audio extraction by codec kind from the PMT walk. Per
/// Squad-37: AAC routes through `extract_ts_aac_audio` (Squad-27 path);
/// AC-3 and E-AC-3 route through their respective new extractors.
pub(super) fn extract_ts_audio(
    data: &[u8],
    packets: usize,
    packet_stride: usize,
    prefix_len: usize,
    info: AudioStreamInfo,
) -> Result<Option<TsAudio>> {
    match info.kind {
        AudioCodecKind::AacAdts => {
            extract_ts_aac_audio(data, packets, packet_stride, prefix_len, info.pid)
        }
        AudioCodecKind::Ac3 => {
            extract_ts_ac3_audio(data, packets, packet_stride, prefix_len, info.pid)
        }
        AudioCodecKind::Eac3 => {
            extract_ts_eac3_audio(data, packets, packet_stride, prefix_len, info.pid)
        }
        AudioCodecKind::MpegAudio => {
            extract_ts_mpeg_audio(data, packets, packet_stride, prefix_len, info.pid)
        }
        AudioCodecKind::Opus { channel_config_code } => {
            extract_ts_opus_audio(data, packets, packet_stride, prefix_len, info.pid, channel_config_code)
        }
        AudioCodecKind::Dts => {
            let (es, pes) = reassemble_audio_pes(data, packets, packet_stride, prefix_len, info.pid);
            let Some((track, starts)) = dts_from_es(&es)? else {
                return Ok(None);
            };
            Ok(Some(TsAudio {
                first_pts: first_frame_pts(&pes, &starts, &track.durations, track.sample_rate),
                pes,
                frame_starts: starts,
                track,
            }))
        }
        AudioCodecKind::Unsupported(name) => bail!("TS: no reader for {name} audio"),
    }
}

/// A program's audio: the stream read (the first of its audio streams that
/// rivet reads, else the first), and — when it is one rivet has no reader
/// for, or its packets would not read — the track named, with no packets,
/// for the job to refuse by name instead of writing the video alone.
pub(super) fn read_program_audio(
    data: &[u8],
    packets: usize,
    packet_stride: usize,
    prefix_len: usize,
    streams: &[AudioStreamInfo],
) -> (Option<TsAudio>, Option<AudioTrack>) {
    let Some(&info) = streams.iter().find(|s| s.kind.is_read()).or(streams.first()) else {
        return (None, None);
    };
    let named = |name: String| AudioTrack {
        codec: name,
        samples: Vec::new(),
        sample_rate: 0,
        channels: 0,
        asc: Vec::new(),
        codec_private: Vec::new(),
        timescale: 1,
        durations: Vec::new(),
    };
    if let AudioCodecKind::Unsupported(name) = info.kind {
        tracing::warn!(audio_pid = info.pid, stream_type = info.stream_type, codec = name, "TS audio stream has no reader in rivet; surfaced by name with no packets");
        return (None, Some(named(name.to_string())));
    }
    match extract_ts_audio(data, packets, packet_stride, prefix_len, info) {
        Ok(audio) => (audio, None),
        Err(e) => {
            tracing::warn!(audio_pid = info.pid, audio_kind = ?info.kind, error = %e, "TS audio extraction failed; the track is surfaced by name with no packets");
            (None, Some(named(format!("unreadable_{}", info.kind.name()))))
        }
    }
}

// ---------------------------------------------------------------------------
// Opus
// ---------------------------------------------------------------------------

/// The OpusHead body (RFC 7845 §5.1, after the magic) for an Opus-in-TS
/// `channel_config_code` (the TS mapping's Table 4-3): 0x00 dual mono;
/// 0x01..=0x08 one to eight channels in the Vorbis order (mapping family 0
/// for one or two channels, 1 beyond, with the RFC 7845 §5.1.1.2 stream
/// counts and mapping); 0x80..=0x86 two to eight channels, family 1, one
/// uncoupled stream each. Anything else (the explicit form included) is
/// refused by name.
pub(crate) fn opus_head_for_ts(channel_config_code: u8, pre_skip: u16) -> Result<Vec<u8>> {
    let (channels, family, streams, coupled, mapping): (u8, u8, u8, u8, Vec<u8>) = match channel_config_code {
        0x00 => (2, 255, 2, 0, vec![0, 1]),
        0x01 => (1, 0, 1, 0, vec![]),
        0x02 => (2, 0, 1, 1, vec![]),
        0x03 => (3, 1, 2, 1, vec![0, 2, 1]),
        0x04 => (4, 1, 2, 2, vec![0, 1, 2, 3]),
        0x05 => (5, 1, 3, 2, vec![0, 4, 1, 2, 3]),
        0x06 => (6, 1, 4, 2, vec![0, 4, 1, 2, 3, 5]),
        0x07 => (7, 1, 4, 3, vec![0, 4, 1, 2, 3, 5, 6]),
        0x08 => (8, 1, 5, 3, vec![0, 6, 1, 2, 3, 4, 5, 7]),
        c @ 0x80..=0x86 => {
            let n = c - 0x7E;
            (n, 1, n, 0, (0..n).collect())
        }
        other => bail!("TS: Opus channel_config_code 0x{other:02X} is not one rivet reads"),
    };
    let mut head = vec![1, channels];
    head.extend_from_slice(&pre_skip.to_le_bytes());
    head.extend_from_slice(&48_000u32.to_le_bytes());
    head.extend_from_slice(&0i16.to_le_bytes());
    head.push(family);
    if family != 0 {
        head.push(streams);
        head.push(coupled);
        head.extend_from_slice(&mapping);
    }
    Ok(head)
}

/// One `opus_control_header` (the TS mapping §6.2): the payload's size and
/// the header's own length, and the start / end trims, in 48 kHz samples.
struct OpusControl {
    header_len: usize,
    payload_size: usize,
    start_trim: u16,
    end_trim: u16,
}

fn parse_opus_control(au: &[u8]) -> Option<OpusControl> {
    // control_header_prefix: 11 bits of 0x3FF, then start_trim_flag,
    // end_trim_flag, control_extension_flag and two reserved bits.
    if au.len() < 3 || au[0] != 0x7F || au[1] & 0xE0 != 0xE0 {
        return None;
    }
    let (start_flag, end_flag, ext_flag) = (au[1] & 0x10 != 0, au[1] & 0x08 != 0, au[1] & 0x04 != 0);
    let mut at = 2;
    let mut payload_size = 0usize;
    loop {
        let b = *au.get(at)?;
        at += 1;
        payload_size += usize::from(b);
        if b != 0xFF {
            break;
        }
    }
    let mut trim = |flag: bool| -> Option<u16> {
        if !flag {
            return Some(0);
        }
        let v = u16::from_be_bytes([*au.get(at)?, *au.get(at + 1)?]) & 0x1FFF;
        at += 2;
        Some(v)
    };
    let start_trim = trim(start_flag)?;
    let end_trim = trim(end_flag)?;
    if ext_flag {
        at += 1 + usize::from(*au.get(at)?);
    }
    Some(OpusControl { header_len: at, payload_size, start_trim, end_trim })
}

/// Extract Opus access units from PES packets on `audio_pid`: each AU's
/// control header stripped (its payload is the Opus packet, or for several
/// streams the self-delimited packets and the last one — the same form an
/// MP4 or Ogg sample takes), one sample per AU; the OpusHead built from the
/// descriptor's channel configuration and the first AU's start trim as its
/// pre-skip. Each AU lasts what its packet's TOC says.
fn extract_ts_opus_audio(
    data: &[u8],
    packets: usize,
    packet_stride: usize,
    prefix_len: usize,
    audio_pid: u16,
    channel_config_code: u8,
) -> Result<Option<TsAudio>> {
    let (es, pes) = reassemble_audio_pes(data, packets, packet_stride, prefix_len, audio_pid);
    if es.is_empty() {
        return Ok(None);
    }
    let mut samples = Vec::new();
    let mut durations = Vec::new();
    let mut starts = Vec::new();
    let mut pre_skip = None;
    let mut end_trim = 0u16;
    // A PES packet holds whole AUs (§6), so each is walked on its own.
    for (i, &(begin, _, _)) in pes.iter().enumerate() {
        let end = pes.get(i + 1).map_or(es.len(), |&(next, _, _)| next);
        let mut at = begin;
        while at < end {
            let au = &es[at..end];
            let (payload, next) = match parse_opus_control(au) {
                Some(c) if c.header_len + c.payload_size <= au.len() => {
                    if pre_skip.is_none() {
                        pre_skip = Some(c.start_trim);
                    }
                    end_trim = c.end_trim;
                    (&au[c.header_len..c.header_len + c.payload_size], at + c.header_len + c.payload_size)
                }
                // No control header: the rest of the PES packet is one AU.
                None => (au, end),
                Some(_) => break,
            };
            if !payload.is_empty() {
                durations.push(crate::ogg::opus_packet_samples(payload).unwrap_or(960));
                samples.push(payload.to_vec());
                starts.push(at);
            }
            at = next;
        }
    }
    if samples.is_empty() {
        return Ok(None);
    }
    if end_trim > 0 {
        tracing::info!(end_trim, "TS Opus: the last access unit's end trim is not applied");
    }
    let head = opus_head_for_ts(channel_config_code, pre_skip.unwrap_or(0))?;
    let channels = u16::from(head[1]);
    Ok(Some(TsAudio {
        first_pts: first_frame_pts(&pes, &starts, &durations, 48_000),
        pes,
        frame_starts: starts,
        track: AudioTrack {
            codec: "opus".into(),
            samples,
            sample_rate: 48_000,
            channels,
            asc: Vec::new(),
            codec_private: head,
            timescale: 48_000,
            durations,
        },
    }))
}

// ---------------------------------------------------------------------------
// DTS
// ---------------------------------------------------------------------------

/// Where the next DTS core sync word (`7F FE 80 01`, the 16-bit big-endian
/// form) is, at or after `from`.
fn find_dts_sync(es: &[u8], from: usize) -> Option<usize> {
    es.get(from..)?.windows(4).position(|w| w == [0x7F, 0xFE, 0x80, 0x01]).map(|i| from + i)
}

/// A DTS track from an elementary stream: one sample per core frame, with
/// the DTS-HD extension substream that follows it (ETSI TS 102 114; the
/// extension is carried, the core decoded); beside it, where each frame
/// starts. The first core header gives the rate, channels and the `ddts`.
/// `None` for a stream with no core frame. Shared by the transport-stream
/// reader and raw `.dts` files.
pub(crate) fn dts_from_es(es: &[u8]) -> Result<Option<(AudioTrack, Vec<usize>)>> {
    let Some(mut cursor) = find_dts_sync(es, 0) else {
        return Ok(None);
    };
    let first = crate::dts_sync::parse_core_sync(&es[cursor..]).map_err(|e| anyhow::anyhow!("TS: first DTS frame: {e}"))?;
    let hd = crate::dts_sync::has_hd_extension(&es[cursor..], &first);
    let mut samples = Vec::new();
    let mut durations = Vec::new();
    let mut starts = Vec::new();
    while let Some(found) = find_dts_sync(es, cursor) {
        cursor = found;
        let Ok(core) = crate::dts_sync::parse_core_sync(&es[cursor..]) else {
            cursor += 1;
            continue;
        };
        if core.sample_rate != first.sample_rate || core.frame_size < 96 {
            cursor += 1;
            continue;
        }
        let core_end = cursor + core.frame_size;
        if core_end > es.len() {
            break;
        }
        // The frame runs to the next core sync: past an extension substream
        // when one follows the core, else the core alone.
        let end = if crate::dts_sync::has_hd_extension(&es[cursor..], &core) {
            find_dts_sync(es, core_end).unwrap_or(es.len())
        } else {
            core_end
        };
        samples.push(es[cursor..end].to_vec());
        durations.push(core.samples_per_frame);
        starts.push(cursor);
        cursor = end;
    }
    if samples.is_empty() {
        return Ok(None);
    }
    if hd {
        tracing::info!("DTS: DTS-HD extension present; carried through, the core decoded");
    }
    Ok(Some((
        AudioTrack {
            codec: "dts".into(),
            samples,
            sample_rate: first.sample_rate,
            channels: first.channels,
            asc: Vec::new(),
            codec_private: crate::mux::ddts_body_from_sync(&first, hd),
            timescale: first.sample_rate,
            durations,
        },
        starts,
    )))
}

/// Extract MPEG audio (MP3 / MP2) frames from PES packets on `audio_pid`:
/// one sample per frame, sliced by [`crate::mp3::frames`], which confirms
/// each header against the next before it trusts it. The first frame's
/// header gives the rate, channel count and layer (`mp3` / `mp2`).
fn extract_ts_mpeg_audio(
    data: &[u8],
    packets: usize,
    packet_stride: usize,
    prefix_len: usize,
    audio_pid: u16,
) -> Result<Option<TsAudio>> {
    let (es, pes) = reassemble_audio_pes(data, packets, packet_stride, prefix_len, audio_pid);
    let Some((track, starts)) = mpeg_audio_from_es(&es) else {
        return Ok(None);
    };
    Ok(Some(TsAudio {
        first_pts: first_frame_pts(&pes, &starts, &track.durations, track.sample_rate),
        pes,
        frame_starts: starts,
        track,
    }))
}

/// An MPEG audio (MP3 / MP2) track from an elementary stream: one sample per
/// frame, sliced by [`crate::mp3::frames`]; beside it, where each kept frame
/// starts. The first frame's header gives the rate, channel count and layer.
/// Shared by the transport-stream and program-stream demuxers.
pub(crate) fn mpeg_audio_from_es(es: &[u8]) -> Option<(AudioTrack, Vec<usize>)> {
    let found = crate::mp3::frames(es);
    let &(_, first) = found.first()?;
    // A stream that changes layer or rate part-way is two streams; keep the
    // first.
    let frames: Vec<_> = found
        .into_iter()
        .take_while(|(_, h)| h.layer == first.layer && h.sample_rate == first.sample_rate)
        .collect();
    let samples = frames.iter().map(|&(at, h)| es[at..at + h.frame_len()].to_vec()).collect();
    let durations: Vec<u32> = frames.iter().map(|(_, h)| h.samples()).collect();
    let starts: Vec<usize> = frames.iter().map(|&(at, _)| at).collect();
    Some((
        AudioTrack {
            codec: first.codec().into(),
            samples,
            sample_rate: first.sample_rate,
            channels: first.channels(),
            asc: Vec::new(),
            codec_private: Vec::new(),
            timescale: first.sample_rate,
            durations,
        },
        starts,
    ))
}
