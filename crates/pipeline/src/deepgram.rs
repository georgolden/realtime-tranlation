//! Deepgram streaming-STT client.
//!
//! One persistent WebSocket connection per track. Audio in (i16 LE @
//! 16 kHz mono), JSON events out. `is_final` segments are accumulated
//! into a local buffer and flushed only when Deepgram signals
//! `speech_final: true` (end of utterance) or on a fallback
//! `UtteranceEnd` event. This trades latency for higher-quality
//! sentences instead of fragmenting every `is_final` word-by-word.

use std::panic::AssertUnwindSafe;
use std::sync::atomic::{AtomicBool, Ordering};
use std::sync::Arc;
use std::time::{SystemTime, UNIX_EPOCH};

use futures_util::{FutureExt, SinkExt, StreamExt};
use serde::Deserialize;
use tokio::sync::mpsc;
use tokio_tungstenite::{
    connect_async,
    tungstenite::{client::IntoClientRequest, http::HeaderValue, Message},
};

use crate::events::{PipelineEvent, TrackId};
use crate::PipelineError;

/// Controls when Deepgram transcripts are flushed to the translation layer.
#[derive(Debug, Clone, Copy, PartialEq, Eq)]
pub enum FlushMode {
    /// Accumulate intermediate `is_final` segments, flush only on
    /// `speech_final: true` or `UtteranceEnd`. Produces complete
    /// sentences at the cost of higher latency. Best for STT → translate
    /// → TTS pipelines where quality matters more than immediacy.
    SpeechFinal,
    /// Flush immediately on every `is_final: true`. Lowest latency,
    /// word-by-word output. Best for subtitle overlays where the user
    /// needs to see words as soon as they're spoken.
    IsFinal,
}

#[derive(Debug, Clone)]
pub struct DeepgramConfig {
    pub api_key:           String,
    pub model:             String,
    /// BCP-47 language code, or `"multi"` for nova-3 multilingual mode
    /// (auto-detects language within the stream). Default is `"multi"`.
    ///
    /// Note: Deepgram's `detect_language=true` param only works for
    /// pre-recorded audio, not streaming. For streaming, `language=multi`
    /// is the correct way to get automatic language detection.
    pub language:          String,
    pub sample_rate:       u32,      // we ship 16_000
    pub channels:          u16,      // we ship 1
    pub interim_results:   bool,     // true
    pub endpointing_ms:    u32,      // 300 (per spec)
    pub utterance_end_ms:  u32,      // 1000 (per spec)
    pub smart_format:      bool,     // true
    pub punctuate:         bool,     // true
    /// Per spec, `endpoint=wss://api.deepgram.com/v1/listen`.
    pub endpoint:          String,
    /// When to flush transcripts to the translation layer.
    /// Default: `SpeechFinal` (accumulate, flush on utterance end).
    pub flush_mode:        FlushMode,
}

impl DeepgramConfig {
    /// Default config: `language=multi` — nova-3 multilingual mode that
    /// auto-detects the language within the stream. This is the correct
    /// streaming equivalent of language detection; `detect_language=true`
    /// is only valid for pre-recorded audio and causes a 400 on streaming.
    ///
    /// **Default values are defined here** — single source of truth used
    /// by both the binary and any future config-file layer.
    pub fn with_detect_language(api_key: String) -> Self {
        Self {
            api_key,
            model:            "nova-3".into(),
            language:         "multi".into(),  // ← nova-3 multilingual auto-detect
            sample_rate:      16_000,
            channels:         1,
            interim_results:  true,
            endpointing_ms:   300,
            utterance_end_ms: 2000,
            smart_format:     true,
            punctuate:        true,
            endpoint:         "wss://api.deepgram.com/v1/listen".into(),
            flush_mode:       FlushMode::SpeechFinal,
        }
    }

    /// Config with an explicit fixed language code (e.g. "en", "de").
    pub fn with_language(api_key: String, language: impl Into<String>) -> Self {
        Self {
            language: language.into(),
            ..Self::with_detect_language(api_key)
        }
    }

    fn build_url(&self) -> String {
        let mut url = self.endpoint.clone();
        url.push('?');

        let pairs: Vec<(&str, String)> = vec![
            ("model",            self.model.clone()),
            ("language",         self.language.clone()),
            ("encoding",         "linear16".into()),
            ("sample_rate",      self.sample_rate.to_string()),
            ("channels",         self.channels.to_string()),
            ("interim_results",  bool_str(self.interim_results).into()),
            ("endpointing",      self.endpointing_ms.to_string()),
            ("utterance_end_ms", self.utterance_end_ms.to_string()),
            ("smart_format",     bool_str(self.smart_format).into()),
            ("punctuate",        bool_str(self.punctuate).into()),
        ];

        url.push_str(
            &pairs
                .iter()
                .map(|(k, v)| format!("{k}={v}"))
                .collect::<Vec<_>>()
                .join("&"),
        );
        url
    }
}

fn bool_str(b: bool) -> &'static str {
    if b { "true" } else { "false" }
}

/// Wall-clock timestamp as `HH:MM:SS.mmm` for latency logging.
fn ts() -> String {
    let ms = SystemTime::now()
        .duration_since(UNIX_EPOCH)
        .unwrap_or_default()
        .as_millis();
    let s  = (ms / 1000) % 86400;
    let h  = s / 3600;
    let m  = (s % 3600) / 60;
    let sc = s % 60;
    let ms = ms % 1000;
    format!("{h:02}:{m:02}:{sc:02}.{ms:03}")
}

/// Handle the caller uses to feed audio in + receive events out.
/// Cloneable — dropping the *last* clone closes the audio channel,
/// at which point the WS task sends `CloseStream` and ends.
#[derive(Clone)]
pub struct DeepgramHandle {
    audio_tx: mpsc::Sender<Vec<i16>>,
    /// Set when the audio channel is observed closed, so we only log
    /// the "client task ended" message once instead of on every push.
    closed_logged: Arc<AtomicBool>,
}

impl DeepgramHandle {
    /// Push 16-bit PCM samples (16 kHz mono) into the stream. Non-
    /// blocking: drops on backpressure with a warning. (Deepgram is
    /// faster than realtime in practice; this should never fire.)
    pub fn push_pcm(&self, samples: Vec<i16>) {
        if samples.is_empty() {
            return;
        }
        match self.audio_tx.try_send(samples) {
            Ok(()) => {}
            Err(mpsc::error::TrySendError::Full(_)) => {
                log::warn!("Deepgram audio queue full — dropping samples");
            }
            Err(mpsc::error::TrySendError::Closed(_)) => {
                if !self.closed_logged.swap(true, Ordering::Relaxed) {
                    log::error!(
                        "Deepgram audio channel closed (client task ended) \
                         — subsequent push_pcm calls will be silently dropped"
                    );
                }
            }
        }
    }

    /// Whether the WS task has ended (audio channel closed). Callers
    /// that pace input may want to stop early instead of pushing into
    /// the void.
    pub fn is_closed(&self) -> bool {
        self.audio_tx.is_closed()
    }
}

pub struct DeepgramClient;

impl DeepgramClient {
    /// Spawn the client. Returns the handle + the event receiver.
    /// Caller can ignore the JoinHandle — the task ends when the
    /// audio channel closes.
    pub fn spawn(
        cfg:   DeepgramConfig,
        track: TrackId,
    ) -> (DeepgramHandle, mpsc::Receiver<PipelineEvent>) {
        // rustls 0.23 panics on first TLS handshake unless a crypto
        // provider has been installed. Doing it here covers every
        // caller (binary or library).
        crate::ensure_crypto_provider();

        // Large enough to absorb ~250ms of WS connect latency at 20ms/chunk
        // (stereo 48kHz → ~10 chunks/s after resample = ~13 chunks burst).
        // 512 gives ~5s of headroom; try_send still drops if truly full.
        let (audio_tx, audio_rx) = mpsc::channel::<Vec<i16>>(512);
        let (event_tx, event_rx) = mpsc::channel::<PipelineEvent>(256);

        tokio::spawn(async move {
            // Catch panics so a bug inside rustls / tungstenite doesn't
            // silently take down the WS task and leave the audio
            // sender hanging open. Without this, every push_pcm logs an
            // error after the panic.
            let result = AssertUnwindSafe(run_client(
                cfg, track, audio_rx, event_tx.clone(),
            ))
            .catch_unwind()
            .await;

            let err_msg = match result {
                Ok(Ok(())) => return,
                Ok(Err(e)) => format!("{e}"),
                Err(panic_payload) => {
                    let s = panic_payload
                        .downcast_ref::<&'static str>()
                        .copied()
                        .or_else(|| {
                            panic_payload
                                .downcast_ref::<String>()
                                .map(String::as_str)
                        })
                        .unwrap_or("<non-string panic>");
                    format!("client task panicked: {s}")
                }
            };
            log::error!("Deepgram client task ended: {err_msg}");
            let _ = event_tx
                .send(PipelineEvent::Error { track, error: err_msg })
                .await;
        });

        (
            DeepgramHandle {
                audio_tx,
                closed_logged: Arc::new(AtomicBool::new(false)),
            },
            event_rx,
        )
    }
}

async fn run_client(
    cfg:        DeepgramConfig,
    track:      TrackId,
    mut audio_rx: mpsc::Receiver<Vec<i16>>,
    event_tx:   mpsc::Sender<PipelineEvent>,
) -> Result<(), PipelineError> {
    let url = cfg.build_url();
    log::info!(
        "Deepgram: connecting — params: {}",
        url.split_once('?').map(|(_, q)| q).unwrap_or("(none)")
    );

    // Build the request manually so we can attach the auth header.
    let mut req = url
        .as_str()
        .into_client_request()
        .map_err(PipelineError::WebSocket)?;
    req.headers_mut().insert(
        "Authorization",
        HeaderValue::from_str(&format!("Token {}", cfg.api_key))
            .map_err(|_| PipelineError::Deepgram("invalid API key header".into()))?,
    );

    let (ws, _resp) = connect_async(req).await.map_err(PipelineError::WebSocket)?;
    log::info!("Deepgram: connected");

    let (mut ws_sink, mut ws_stream) = ws.split();
    let mut stt_buf = String::new();
    let flush_mode = cfg.flush_mode;
    log::info!("Deepgram: flush_mode={:?}", flush_mode);

    loop {
        tokio::select! {
            maybe_samples = audio_rx.recv() => {
                match maybe_samples {
                    Some(samples) => {
                        let bytes = i16_le_bytes(&samples);
                        if let Err(e) = ws_sink.send(Message::Binary(bytes.into())).await {
                            log::error!("Deepgram: ws send failed: {e}");
                            return Err(PipelineError::WebSocket(e));
                        }
                    }
                    None => {
                        let close = serde_json::json!({ "type": "CloseStream" });
                        let _ = ws_sink.send(Message::Text(close.to_string().into())).await;
                        break;
                    }
                }
            }

            maybe_msg = ws_stream.next() => {
                match maybe_msg {
                    Some(Ok(msg)) => {
                        if let Err(e) = handle_ws_message(msg, &event_tx, track, &mut stt_buf, flush_mode).await {
                            log::warn!("Deepgram: bad ws message: {e}");
                        }
                    }
                    Some(Err(e)) => {
                        log::error!("Deepgram: ws error: {e}");
                        return Err(PipelineError::WebSocket(e));
                    }
                    None => {
                        log::info!("Deepgram: ws closed");
                        break;
                    }
                }
            }
        }
    }

    // Drain tail finals after CloseStream.
    while let Some(msg) = ws_stream.next().await {
        match msg {
            Ok(m) => { let _ = handle_ws_message(m, &event_tx, track, &mut stt_buf, flush_mode).await; }
            Err(_) => break,
        }
    }

    // Flush any remaining buffered text after the stream closes.
    // Only relevant for SpeechFinal mode (IsFinal mode flushes immediately).
    if !stt_buf.is_empty() {
        let text = std::mem::take(&mut stt_buf);
        log::info!("[{}] Stream ended — flushing remaining buffer ({}B): {:?}", ts(), text.len(), text);
        let _ = event_tx.send(PipelineEvent::Flushed {
            track,
            text,
            reason: "stream-end",
        }).await;
    }

    Ok(())
}

async fn handle_ws_message(
    msg:        Message,
    event_tx:   &mpsc::Sender<PipelineEvent>,
    track:      TrackId,
    stt_buf:    &mut String,
    flush_mode: FlushMode,
) -> Result<(), PipelineError> {
    let text = match msg {
        Message::Text(t) => t,
        Message::Binary(_) | Message::Ping(_) | Message::Pong(_) | Message::Frame(_) => return Ok(()),
        Message::Close(_) => return Ok(()),
    };

    let raw: serde_json::Value = serde_json::from_str(&text)?;
    let kind = raw.get("type").and_then(|t| t.as_str()).unwrap_or("");

    match kind {
        "Results" => {
            let parsed: ResultsMsg = serde_json::from_value(raw)?;
            handle_result(parsed, event_tx, track, stt_buf, flush_mode).await;
        }
        "UtteranceEnd" => {
            if flush_mode == FlushMode::IsFinal {
                log::info!("[{}] UtteranceEnd (no-op in IsFinal mode)", ts());
            } else if !stt_buf.is_empty() {
                log::info!("[{}] UtteranceEnd — buffer len={}", ts(), stt_buf.len());
                let text = std::mem::take(stt_buf);
                log::info!("[{}] UtteranceEnd flush: {:?}", ts(), text);
                let _ = event_tx.send(PipelineEvent::Flushed {
                    track,
                    text,
                    reason: "utterance-end",
                }).await;
            }
        }
        "SpeechStarted" => log::info!("[{}] SpeechStarted", ts()),
        "Metadata" | "Warning" => log::trace!("Deepgram: {kind}"),
        other => log::trace!("Deepgram: unknown message type '{other}'"),
    }
    Ok(())
}

async fn handle_result(
    msg:        ResultsMsg,
    event_tx:   &mpsc::Sender<PipelineEvent>,
    track:      TrackId,
    stt_buf:    &mut String,
    flush_mode: FlushMode,
) {
    let transcript = msg
        .channel
        .alternatives
        .first()
        .map(|a| a.transcript.as_str())
        .unwrap_or("");

    if msg.is_final {
        if transcript.trim().is_empty() {
            log::info!("[{}] is_final speech_final={} EMPTY (skipped)", ts(), msg.speech_final);
            return;
        }

        if flush_mode == FlushMode::IsFinal {
            // IsFinal mode: flush immediately on every is_final. Lowest
            // latency for subtitle overlays — user sees words as spoken.
            log::info!(
                "[{}] is_final (IsFinal mode) → flush: {:?}",
                ts(),
                transcript,
            );
            let _ = event_tx.send(PipelineEvent::Flushed {
                track,
                text: transcript.trim().to_string(),
                reason: "is-final",
            }).await;
            return;
        }

        // SpeechFinal mode: accumulate intermediate finals, flush on speech_final.
        if msg.speech_final {
            let mut full = std::mem::take(stt_buf);
            if !full.is_empty() {
                full.push(' ');
            }
            full.push_str(transcript.trim());
            log::info!(
                "[{}] speech_final=true → flush (buf_was={}B, result={}B): {:?}",
                ts(),
                stt_buf.len(),
                full.len(),
                full,
            );
            let _ = event_tx.send(PipelineEvent::Flushed {
                track,
                text: full,
                reason: "speech-final",
            }).await;
        } else {
            if !stt_buf.is_empty() {
                stt_buf.push(' ');
            }
            stt_buf.push_str(transcript.trim());
            log::info!(
                "[{}] is_final speech_final=false → buffer (len={}): {:?}",
                ts(),
                stt_buf.len(),
                transcript,
            );
        }
    } else {
        if transcript.trim().is_empty() {
            return;
        }
        log::info!("[{}] partial={:?}", ts(), transcript);
        let _ = event_tx.send(PipelineEvent::Partial {
            track,
            text: transcript.to_string(),
        }).await;
    }
}

fn i16_le_bytes(samples: &[i16]) -> Vec<u8> {
    let mut out = Vec::with_capacity(samples.len() * 2);
    for &s in samples {
        out.extend_from_slice(&s.to_le_bytes());
    }
    out
}

// --- Deepgram message schema (just the fields we use). ---
// Full schema is much larger; we tolerate unknown fields with serde's
// default behaviour.

#[derive(Debug, Deserialize)]
struct ResultsMsg {
    #[serde(default)]
    is_final: bool,
    #[serde(default)]
    speech_final: bool,
    channel: Channel,
}

#[derive(Debug, Deserialize)]
struct Channel {
    alternatives: Vec<Alternative>,
}

#[derive(Debug, Deserialize)]
struct Alternative {
    transcript: String,
}

#[cfg(test)]
mod tests {
    use super::*;

    // ── URL-building tests ────────────────────────────────────────────────
    // Default values live in `DeepgramConfig::with_detect_language`.
    // These tests are the machine-readable spec for what lands in the URL.

    // ── URL-building tests ────────────────────────────────────────────────
    // Default values live in `DeepgramConfig::with_detect_language`.
    // These tests are the machine-readable spec for what lands in the URL.

    #[test]
    fn url_auto_detect_uses_multi() {
        // Default (no explicit language) → language=multi in URL.
        // detect_language=true is NOT used — it's only valid for pre-recorded
        // audio, not streaming. nova-3 language=multi is the streaming equivalent.
        let cfg = DeepgramConfig::with_detect_language("dummy".into());
        let url = cfg.build_url();
        assert!(url.starts_with("wss://api.deepgram.com/v1/listen?"));
        assert!(url.contains("language=multi"), "missing language=multi in {url}");
        assert!(!url.contains("detect_language"), "detect_language must not appear in streaming URL: {url}");
        for needle in [
            "model=nova-3",
            "encoding=linear16",
            "sample_rate=16000",
            "channels=1",
            "interim_results=true",
            "endpointing=300",
            "utterance_end_ms=2000",
            "smart_format=true",
            "punctuate=true",
        ] {
            assert!(url.contains(needle), "missing {needle} in {url}");
        }
    }

    #[test]
    fn url_explicit_language_en() {
        let cfg = DeepgramConfig::with_language("dummy".into(), "en");
        let url = cfg.build_url();
        assert!(url.contains("language=en"), "missing language=en in {url}");
        assert!(!url.contains("detect_language"), "detect_language must be absent: {url}");
    }

    #[test]
    fn url_explicit_language_de() {
        let cfg = DeepgramConfig::with_language("dummy".into(), "de");
        let url = cfg.build_url();
        assert!(url.contains("language=de"), "missing language=de in {url}");
        assert!(!url.contains("detect_language"), "detect_language must be absent: {url}");
    }

    #[test]
    fn parse_results_message() {
        // Captured-shape fixture matching what Deepgram actually sends.
        let s = r#"{
            "type": "Results",
            "channel_index": [0,1],
            "duration": 1.0,
            "start": 0.0,
            "is_final": true,
            "speech_final": true,
            "channel": {
                "alternatives": [{
                    "transcript": "hello world",
                    "confidence": 0.99,
                    "words": []
                }]
            }
        }"#;
        let v: serde_json::Value = serde_json::from_str(s).unwrap();
        let kind = v.get("type").and_then(|t| t.as_str()).unwrap();
        assert_eq!(kind, "Results");
        let r: ResultsMsg = serde_json::from_value(v).unwrap();
        assert!(r.is_final);
        assert_eq!(r.channel.alternatives[0].transcript, "hello world");
    }

    #[test]
    fn i16_to_le_round_trip() {
        let samples: Vec<i16> = vec![0, 1, -1, 32767, -32768];
        let bytes = i16_le_bytes(&samples);
        assert_eq!(bytes.len(), samples.len() * 2);
        // First sample is 0x0000.
        assert_eq!(&bytes[0..2], &[0u8, 0u8]);
        // Last sample is 0x8000 little-endian = [0x00, 0x80].
        assert_eq!(&bytes[bytes.len() - 2..], &[0x00, 0x80]);
    }
}
