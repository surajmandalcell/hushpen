//! Heavy integration tests: the real whisper engine with a real model.
//!
//! Inputs: `HUSHPEN_TEST_MODEL` (a ggml model file) or `HUSHPEN_TEST_ASSETS`
//! (`models/whisper/ggml-tiny.en.bin`). The short clip falls back to `tests/fixtures`.
//! `HUSHPEN_TEST_GPU=1` turns on the GPU test (Metal, macOS only).
#![cfg(feature = "heavy")]

use std::path::PathBuf;
use std::thread;
use std::time::{Duration, Instant};

use hushpen_engine::{
    AsrEngine, CancelFlag, EngineError, LoadOptions, TranscribeOptions, WhisperEngine,
};

// The child process and supervisor tests share the helpers below.
#[path = "it/child.rs"]
mod child;
#[path = "it/import.rs"]
mod import;
#[path = "it/parakeet.rs"]
mod parakeet;
#[path = "it/silence.rs"]
mod silence;

fn assets_dir() -> Option<PathBuf> {
    std::env::var_os("HUSHPEN_TEST_ASSETS").map(PathBuf::from)
}

fn model_path() -> PathBuf {
    if let Some(path) = std::env::var_os("HUSHPEN_TEST_MODEL") {
        return path.into();
    }
    let path = assets_dir()
        .expect("set HUSHPEN_TEST_MODEL or HUSHPEN_TEST_ASSETS")
        .join("models/whisper/ggml-tiny.en.bin");
    assert!(path.exists(), "missing model {}", path.display());
    path
}

fn short_wav() -> PathBuf {
    let shared = assets_dir().map(|d| d.join("fixtures/speech-short.wav"));
    match shared {
        Some(path) if path.exists() => path,
        _ => PathBuf::from(env!("CARGO_MANIFEST_DIR")).join("tests/fixtures/speech-short.wav"),
    }
}

fn read_wav(path: &std::path::Path) -> Vec<f32> {
    let mut reader = hound::WavReader::open(path).expect("open wav");
    let spec = reader.spec();
    assert_eq!(spec.sample_rate, 16_000);
    assert_eq!(spec.channels, 1);
    reader
        .samples::<i16>()
        .map(|s| f32::from(s.expect("sample")) / 32768.0)
        .collect()
}

/// The 10 minute fixture when the shared assets have it, else the short clip repeated.
fn long_pcm() -> Vec<f32> {
    if let Some(dir) = assets_dir() {
        let path = dir.join("fixtures/long-600s.wav");
        if path.exists() {
            return read_wav(&path);
        }
    }
    let clip = read_wav(&short_wav());
    clip.iter().copied().cycle().take(16_000 * 600).collect()
}

fn words(text: &str) -> String {
    text.to_lowercase()
        .chars()
        .map(|c| if c.is_alphanumeric() { c } else { ' ' })
        .collect::<String>()
        .split_whitespace()
        .collect::<Vec<_>>()
        .join(" ")
}

fn load(gpu: bool) -> WhisperEngine {
    WhisperEngine::load(&model_path(), LoadOptions { gpu, threads: 2 }).expect("load model")
}

fn english() -> TranscribeOptions {
    TranscribeOptions {
        language: Some("en".into()),
        ..TranscribeOptions::default()
    }
}

fn assert_expected_words(text: &str) {
    let got = words(text);
    assert!(
        got.contains("the quick brown fox jumps over the lazy dog numbers"),
        "unexpected transcript: {got}"
    );
    assert!(
        ["1 2 3 4 5", "12345", "one two three four five"]
            .iter()
            .any(|tail| got.ends_with(tail)),
        "unexpected transcript tail: {got}"
    );
}

#[test]
fn a_paged_out_model_gives_the_same_transcript() {
    let mut engine = load(false);
    let pcm = read_wav(&short_wav());
    let first = engine
        .transcribe(&pcm, &english(), &CancelFlag::new())
        .expect("transcribe");
    let advised = engine.page_out().expect("page out");
    if cfg!(target_os = "linux") {
        let file = std::fs::metadata(model_path()).unwrap().len();
        assert!(
            advised >= file / 2,
            "advised {advised} of a {file} byte model"
        );
    } else {
        assert_eq!(advised, 0, "only Linux has MADV_PAGEOUT");
    }
    let again = engine
        .transcribe(&pcm, &english(), &CancelFlag::new())
        .expect("transcribe after the page-out");
    assert_eq!(again.text, first.text);
}

#[test]
fn transcribes_short_clip_on_cpu() {
    let mut engine = load(false);
    assert!(!engine.gpu_in_use());
    let result = engine
        .transcribe(&read_wav(&short_wav()), &english(), &CancelFlag::new())
        .expect("transcribe");
    assert_expected_words(&result.text);
    assert_eq!(result.language, "en");
    assert!(!result.segments.is_empty());
    let mut last_start = 0;
    for segment in &result.segments {
        assert!(segment.start_ms < segment.end_ms);
        assert!(segment.start_ms >= last_start);
        last_start = segment.start_ms;
    }
}

#[test]
fn transcribes_short_clip_on_gpu() {
    if std::env::var("HUSHPEN_TEST_GPU").as_deref() != Ok("1") {
        eprintln!("skipped: HUSHPEN_TEST_GPU is not 1");
        return;
    }
    let mut engine = load(true);
    assert_eq!(engine.gpu_in_use(), cfg!(target_os = "macos"));
    let result = engine
        .transcribe(&read_wav(&short_wav()), &english(), &CancelFlag::new())
        .expect("transcribe");
    assert_expected_words(&result.text);
}

/// The clip cut right after its last loud sample: it ends on speech with no trailing silence.
fn cut_at_last_speech(pcm: &[f32]) -> Vec<f32> {
    let last = pcm.iter().rposition(|s| s.abs() > 0.01).expect("speech");
    pcm[..=last].to_vec()
}

#[test]
fn a_clip_that_ends_on_speech_keeps_its_last_word() {
    let mut engine = load(false);
    let clip = cut_at_last_speech(&read_wav(&short_wav()));
    let result = engine
        .transcribe(&clip, &english(), &CancelFlag::new())
        .expect("transcribe");
    assert_expected_words(&result.text);
    let audio_ms = clip.len() as u64 * 1000 / 16_000;
    for segment in &result.segments {
        assert!(
            segment.end_ms <= audio_ms,
            "a segment runs past the audio into the pad: {segment:?}"
        );
    }

    let Some(long) = assets_dir().map(|d| d.join("fixtures/dictation-45s.wav")) else {
        return;
    };
    if !long.exists() {
        return;
    }
    let clip = cut_at_last_speech(&read_wav(&long));
    let result = engine
        .transcribe(&clip, &english(), &CancelFlag::new())
        .expect("transcribe");
    assert!(
        words(&result.text).ends_with("the final word of this dictation is lighthouse"),
        "unexpected transcript tail: {}",
        words(&result.text)
    );
}

#[test]
fn detects_language_when_none_is_given() {
    let mut engine = load(false);
    let result = engine
        .transcribe(
            &read_wav(&short_wav()),
            &TranscribeOptions::default(),
            &CancelFlag::new(),
        )
        .expect("transcribe");
    assert_eq!(result.language, "en");
}

#[test]
fn rejects_an_unknown_language_code() {
    let mut engine = load(false);
    let err = engine
        .transcribe(
            &read_wav(&short_wav()),
            &TranscribeOptions {
                language: Some("xx".into()),
                ..TranscribeOptions::default()
            },
            &CancelFlag::new(),
        )
        .expect_err("bad language");
    assert_eq!(err, EngineError::BadLanguage("xx".into()));
}

fn translate() -> TranscribeOptions {
    TranscribeOptions {
        translate: true,
        ..TranscribeOptions::default()
    }
}

#[test]
fn an_english_only_model_refuses_to_translate() {
    let mut engine = load(false);
    let err = engine
        .transcribe(&read_wav(&short_wav()), &translate(), &CancelFlag::new())
        .expect_err("tiny.en cannot translate");
    assert_eq!(err, EngineError::TranslateUnsupported);
    assert_eq!(
        err.code(),
        Some(hushpen_core::error::ENGINE_TRANSLATE_UNSUPPORTED)
    );
}

#[test]
fn a_spanish_clip_translates_to_english() {
    let dir = assets_dir().expect("HUSHPEN_TEST_ASSETS has ggml-base.bin and speech-es.wav");
    let mut engine = WhisperEngine::load(
        &dir.join("models/whisper/ggml-base.bin"),
        LoadOptions {
            gpu: false,
            threads: 2,
        },
    )
    .expect("load base");
    let pcm = read_wav(&dir.join("fixtures/speech-es.wav"));
    let result = engine
        .transcribe(&pcm, &translate(), &CancelFlag::new())
        .expect("translate");
    let text = words(&result.text);
    eprintln!("translated: {text}");
    assert_eq!(result.language, "es");
    assert!(text.contains("my name is paulina"), "{text}");
    assert!(!text.contains("llamo"), "{text}");
}

#[test]
fn a_missing_model_is_a_load_error() {
    let err = WhisperEngine::load(
        std::path::Path::new("/nonexistent/model.bin"),
        LoadOptions {
            gpu: false,
            threads: 2,
        },
    )
    .err()
    .expect("load must fail");
    assert_eq!(err.code(), Some("ENGINE_LOAD_FAILED"));
}

#[test]
fn a_flag_set_before_the_job_cancels_at_once() {
    let mut engine = load(false);
    let cancel = CancelFlag::new();
    cancel.cancel();
    let started = Instant::now();
    let err = engine
        .transcribe(&read_wav(&short_wav()), &english(), &cancel)
        .expect_err("cancelled");
    let took = started.elapsed();
    eprintln!("pre-set flag: returned after {took:?}");
    assert_eq!(err, EngineError::Cancelled);
    assert!(took < Duration::from_secs(1), "took {took:?}");
}

/// Aborts a 10 minute job once at 0.5 s (encoder phase) and once at 5 s (decode phase).
#[test]
fn abort_of_a_long_job_returns_within_one_second() {
    let mut engine = load(false);
    let pcm = long_pcm();
    for delay_ms in [500_u64, 5_000] {
        let cancel = CancelFlag::new();
        let trigger = cancel.clone();
        let (tx, rx) = std::sync::mpsc::channel();
        let timer = thread::spawn(move || {
            thread::sleep(Duration::from_millis(delay_ms));
            trigger.cancel();
            tx.send(Instant::now()).expect("send");
        });
        let result = engine.transcribe(&pcm, &english(), &cancel);
        let returned = Instant::now();
        timer.join().expect("timer");
        let set_at = rx.recv().expect("set time");
        let latency = returned.saturating_duration_since(set_at);
        eprintln!("abort at {delay_ms} ms: returned {latency:?} after the flag was set");
        assert_eq!(
            result,
            Err(EngineError::Cancelled),
            "abort at {delay_ms} ms"
        );
        assert!(latency < Duration::from_secs(1), "abort took {latency:?}");
    }
}

/// 130 s of speech is two windows; the merge must keep time order and not repeat the overlap.
#[test]
fn long_input_is_merged_in_time_order() {
    let mut engine = load(false);
    let clip = read_wav(&short_wav());
    let pcm: Vec<f32> = clip.iter().copied().cycle().take(16_000 * 130).collect();
    let result = engine
        .transcribe(&pcm, &english(), &CancelFlag::new())
        .expect("transcribe");
    // A segment that straddles the hand-over point may start inside the previous one, but the
    // end times still rise.
    let mut last_end = 0;
    for segment in &result.segments {
        assert!(segment.start_ms < segment.end_ms);
        assert!(segment.end_ms >= last_end, "segments out of order");
        last_end = segment.end_ms;
    }
    assert!(last_end > 120_000, "no segment from the second window");
    let fox = words(&result.text).matches("quick brown fox").count();
    assert!(
        (22..=27).contains(&fox),
        "expected about 25 repeats, got {fox}"
    );
}

/// Prints the release-to-text time of the short clip for each model in `HUSHPEN_TEST_MODELS`
/// (comma-separated paths). Run by hand to refresh the table in `library/engine.md`:
/// `cargo test -p hushpen-engine --features heavy --release --test it measure_latency -- --ignored --nocapture`.
/// `HUSHPEN_TEST_GPU=1` measures Metal; `HUSHPEN_TEST_THREADS` sets the CPU thread count.
#[test]
#[ignore = "a measurement, not a check"]
fn measure_latency() {
    let models = std::env::var("HUSHPEN_TEST_MODELS").expect("set HUSHPEN_TEST_MODELS");
    let gpu = std::env::var("HUSHPEN_TEST_GPU").as_deref() == Ok("1");
    let threads = std::env::var("HUSHPEN_TEST_THREADS")
        .ok()
        .and_then(|value| value.parse().ok())
        .unwrap_or(2);
    let pcm = read_wav(&short_wav());
    for path in models.split(',').map(PathBuf::from) {
        let loaded = Instant::now();
        let mut engine =
            WhisperEngine::load(&path, LoadOptions { gpu, threads }).expect("load model");
        let load_ms = loaded.elapsed().as_millis();
        let mut runs = Vec::new();
        let mut text = String::new();
        for _ in 0..8 {
            let started = Instant::now();
            let result = engine
                .transcribe(&pcm, &english(), &CancelFlag::new())
                .expect("transcribe");
            runs.push(started.elapsed().as_millis());
            text = result.text;
        }
        let first = runs[0];
        let mut warm = runs[1..].to_vec();
        warm.sort_unstable();
        eprintln!(
            "LATENCY model={} gpu={} threads={threads} load_ms={load_ms} first_ms={first} warm_median_ms={} warm_min_ms={} text={:?}",
            path.file_name().unwrap().to_string_lossy(),
            engine.gpu_in_use(),
            warm[warm.len() / 2],
            warm[0],
            text.trim()
        );
    }
}

/// The raw callback must not stop a job whose flag is never set.
#[test]
fn a_job_without_cancel_runs_to_the_full_text() {
    let mut engine = load(false);
    let cancel = CancelFlag::new();
    let result = engine
        .transcribe(&read_wav(&short_wav()), &english(), &cancel)
        .expect("transcribe");
    assert!(!cancel.is_cancelled());
    assert_expected_words(&result.text);
}
