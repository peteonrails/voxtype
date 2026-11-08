//! Eager input processing module
//!
//! Handles chunking audio during recording and processing chunks in parallel
//! with continued recording. This reduces perceived latency on slower machines.
//!
//! The basic approach:
//! 1. During recording, cut the audio into consecutive, non-overlapping chunks.
//!    Each cut lands on the quietest point near the nominal chunk length, so
//!    it falls between words rather than through one.
//! 2. As each chunk is ready, spawn a transcription task for it
//! 3. Continue recording while transcription runs in parallel
//! 4. At the end, transcribe the tail and join the chunk texts in order
//!
//! Chunks used to overlap and the joined text was deduplicated at each
//! boundary by matching words. That both missed duplicates (punctuation made
//! "dictation." and "dictation" differ) and could not tell a duplicate from a
//! word the speaker really said twice. Disjoint chunks need no deduplication.

use crate::state::ChunkResult;

/// Length of the energy frames used to find a quiet cut point (20ms at 16kHz).
const FRAME_SAMPLES: usize = 320;

/// Longest stretch before the nominal boundary searched for a quiet cut.
const MAX_SEARCH_SECS: f32 = 1.5;

/// Configuration for eager processing
#[derive(Debug, Clone)]
pub struct EagerConfig {
    /// Nominal duration of each chunk in seconds. Actual chunks end at the
    /// quietest point within the search window before this length.
    pub chunk_secs: f32,
    /// Sample rate (assumed 16kHz for whisper)
    pub sample_rate: u32,
}

impl EagerConfig {
    /// Create config from whisper config settings
    pub fn from_whisper_config(config: &crate::config::WhisperConfig) -> Self {
        Self {
            chunk_secs: config.eager_chunk_secs,
            sample_rate: 16000, // Whisper expects 16kHz
        }
    }

    /// Get nominal chunk size in samples
    pub fn chunk_samples(&self) -> usize {
        ((self.chunk_secs * self.sample_rate as f32) as usize).max(FRAME_SAMPLES)
    }

    /// Samples before the nominal boundary searched for the quietest cut:
    /// up to 1.5s, never more than half a chunk.
    pub fn search_samples(&self) -> usize {
        let max = (MAX_SEARCH_SECS * self.sample_rate as f32) as usize;
        max.min(self.chunk_samples() / 2)
    }
}

/// Mean energy of each `FRAME_SAMPLES` frame in `audio[lo..hi]`, as
/// `(frame_start, mean_square)`. A trailing partial frame is ignored.
fn frame_energies(audio: &[f32], lo: usize, hi: usize) -> impl Iterator<Item = (usize, f32)> + '_ {
    (lo..hi.saturating_sub(FRAME_SAMPLES - 1))
        .step_by(FRAME_SAMPLES)
        .map(move |start| {
            let frame = &audio[start..start + FRAME_SAMPLES];
            let energy = frame.iter().map(|s| s * s).sum::<f32>() / FRAME_SAMPLES as f32;
            (start, energy)
        })
}

/// Frames in the quiet stretch a cut must sit in (120ms). A single quiet
/// frame is not enough: the closure of a stop consonant ("dicta|tion") is
/// near-silent for 30-80ms, and cutting there splits the word. A pause
/// between words lasts longer.
const QUIET_SPAN_FRAMES: usize = 6;

/// The cut point inside `audio[lo..hi]`: the middle of its quietest
/// `QUIET_SPAN_FRAMES`-frame stretch (fewer if the window is shorter). Ties
/// go to the latest stretch so chunks stay as close to nominal length as the
/// audio allows. Falls back to `hi` when the window holds no full frame.
fn quietest_cut(audio: &[f32], lo: usize, hi: usize) -> usize {
    let frames: Vec<(usize, f32)> = frame_energies(audio, lo, hi).collect();
    if frames.is_empty() {
        return hi;
    }
    let span = QUIET_SPAN_FRAMES.min(frames.len());
    // At most ~75 frames in a 1.5s window, so summing each stretch directly
    // is cheap and avoids running-sum drift deciding ties.
    let mut best = (0, f32::INFINITY);
    for i in 0..=frames.len() - span {
        let sum: f32 = frames[i..i + span].iter().map(|(_, e)| e).sum();
        if sum <= best.1 {
            best = (i, sum);
        }
    }
    let first = frames[best.0].0;
    let last = frames[best.0 + span - 1].0 + FRAME_SAMPLES;
    (first + last) / 2
}

/// End positions of every complete chunk in `audio`. Chunk `k` covers
/// `boundaries[k-1]..boundaries[k]` (chunk 0 starts at 0), so chunks are
/// contiguous and never overlap.
///
/// A boundary depends only on the audio before it, so the result for a
/// shorter prefix of the same recording is always a prefix of the result for
/// the longer one. That lets the daemon recompute boundaries on every poll
/// and trust that chunks it already sent keep the same bounds.
pub fn chunk_boundaries(audio: &[f32], config: &EagerConfig) -> Vec<usize> {
    let chunk = config.chunk_samples();
    let search = config.search_samples();
    let mut boundaries = Vec::new();
    let mut start = 0;
    while start + chunk <= audio.len() {
        let nominal = start + chunk;
        let cut = quietest_cut(audio, nominal - search, nominal);
        boundaries.push(cut);
        start = cut;
    }
    boundaries
}

/// Split a finished recording into windows no longer than `max_window`
/// samples, for engines that cannot take the whole recording in one pass.
///
/// Audio that already fits comes back as a single `(0, len)` range, so short
/// recordings take exactly the path they always did. Longer audio is cut the
/// same way eager chunks are: contiguous, non-overlapping windows that end at
/// the quietest stretch within `search` samples before each nominal boundary.
/// The nominal length is what remains divided evenly over the windows still
/// needed, so the last window is never a sliver, and every window stays
/// within `max_window` because a cut never lands after its nominal boundary.
pub fn long_audio_windows(audio: &[f32], max_window: usize, search: usize) -> Vec<(usize, usize)> {
    let len = audio.len();
    let max_window = max_window.max(2 * FRAME_SAMPLES);
    if len <= max_window {
        return vec![(0, len)];
    }
    let search = search.min(max_window / 2);
    let mut windows = Vec::new();
    let mut start = 0;
    while len - start > max_window {
        let remaining = len - start;
        let nominal = start + remaining / remaining.div_ceil(max_window);
        let cut = quietest_cut(audio, nominal - search, nominal).max(start + 1);
        windows.push((start, cut));
        start = cut;
    }
    windows.push((start, len));
    windows
}

/// Sample range of chunk `index`, or None if that chunk isn't complete yet.
pub fn chunk_range(boundaries: &[usize], index: usize) -> Option<(usize, usize)> {
    let end = *boundaries.get(index)?;
    let start = if index == 0 { 0 } else { boundaries[index - 1] };
    Some((start, end))
}

/// Where the tail begins once `chunks_sent` chunks have been transcribed.
pub fn tail_start(boundaries: &[usize], chunks_sent: usize) -> usize {
    match chunks_sent {
        0 => 0,
        n => boundaries.get(n - 1).copied().unwrap_or(0),
    }
}

/// Join transcription results from multiple chunks in chunk order.
///
/// Chunks are disjoint, so every word belongs to exactly one chunk and the
/// texts are concatenated, with punctuation the engine added only because of
/// the cut smoothed away (see `smooth_boundary`). Empty chunks (silence,
/// failures) are skipped without leaving a double space.
///
/// # Arguments
/// * `results` - Vector of chunk results (may be in any order)
///
/// # Returns
/// Combined transcription text
pub fn combine_chunk_results(mut results: Vec<ChunkResult>) -> String {
    results.sort_by_key(|r| r.chunk_index);
    let mut texts: Vec<String> = results
        .iter()
        .map(|r| r.text.trim().to_string())
        .filter(|t| !t.is_empty())
        .collect();
    for i in 1..texts.len() {
        let (before, after) = texts.split_at_mut(i);
        smooth_boundary(&mut before[i - 1], &mut after[0]);
    }
    texts.join(" ")
}

/// Common words an engine capitalizes only because it saw them at the start
/// of a chunk. Proper nouns and acronyms can't be told apart from these by
/// casing, so anything not listed is left alone.
const SENTENCE_START_WORDS: &[&str] = &[
    "The", "A", "An", "And", "But", "Or", "So", "To", "Of", "In", "On", "At", "For", "With", "As",
    "It", "Is", "Was", "Are", "Be", "That", "This", "Then", "There", "We", "You", "They", "He",
    "She", "If", "Not", "What", "Which", "Who", "When", "Where", "How",
];

/// Abbreviations whose trailing period is part of the word.
const ABBREVIATIONS: &[&str] = &[
    "Mr.", "Mrs.", "Ms.", "Dr.", "St.", "Jr.", "Sr.", "vs.", "etc.",
];

/// Undo punctuation an engine added only because a chunk was cut mid-sentence.
///
/// Each chunk is transcribed on its own, so the engine may end it with a
/// period ("the chunk.") or open the next with sentence casing ("The next")
/// even though the speaker never paused. Conservative on purpose: a period
/// goes only when the next chunk continues in lowercase, a capital goes only
/// on a listed function word after an unpunctuated end, and "?", "!",
/// ellipses, abbreviations, "I", acronyms and proper nouns are never touched.
fn smooth_boundary(prev: &mut String, next: &mut String) {
    let Some(first_word) = next.split_whitespace().next() else {
        return;
    };
    let Some(last_word) = prev.split_whitespace().last() else {
        return;
    };
    let next_starts_lowercase = first_word.chars().next().is_some_and(|c| c.is_lowercase());

    // "the chunk." + "boundaries are..." -> "the chunk boundaries are..."
    let stray_period = last_word.ends_with('.')
        && !last_word.ends_with("..")
        // e.g. / U.S.: an internal period means the word owns its period.
        && !last_word[..last_word.len() - 1].contains('.')
        && !ABBREVIATIONS.contains(&last_word);
    if stray_period && next_starts_lowercase {
        prev.pop();
        return;
    }

    // "we moved to" + "The new office" -> "we moved to the new office"
    let prev_unpunctuated = prev.chars().last().is_some_and(|c| c.is_alphanumeric());
    let bare_first = first_word.trim_end_matches(|c: char| !c.is_alphanumeric());
    if prev_unpunctuated && SENTENCE_START_WORDS.contains(&bare_first) {
        let mut chars = next.chars();
        if let Some(c) = chars.next() {
            *next = c.to_lowercase().chain(chars).collect();
        }
    }
}

#[cfg(test)]
mod tests {
    use super::*;

    const SR: usize = 16000;

    fn test_config() -> EagerConfig {
        EagerConfig {
            chunk_secs: 5.0,
            sample_rate: 16000,
        }
    }

    /// Continuous "speech" (a loud tone) with silent gaps at the given
    /// second offsets, each gap `gap_ms` long.
    fn speech_with_gaps(total_secs: f32, gaps_at: &[f32], gap_ms: usize) -> Vec<f32> {
        let len = (total_secs * SR as f32) as usize;
        let mut audio: Vec<f32> = (0..len).map(|i| 0.5 * (i as f32 * 0.07).sin()).collect();
        for &at in gaps_at {
            let start = (at * SR as f32) as usize;
            let end = (start + gap_ms * SR / 1000).min(len);
            audio[start..end].iter_mut().for_each(|s| *s = 0.0);
        }
        audio
    }

    fn result(text: &str, chunk_index: usize) -> ChunkResult {
        ChunkResult {
            text: text.to_string(),
            chunk_index,
        }
    }

    #[test]
    fn search_window_is_capped_at_half_a_chunk() {
        assert_eq!(test_config().search_samples(), 24000); // 1.5s
        let short = EagerConfig {
            chunk_secs: 2.0,
            sample_rate: 16000,
        };
        assert_eq!(short.search_samples(), 16000); // half of 2s
    }

    #[test]
    fn no_boundaries_before_a_full_chunk() {
        let config = test_config();
        assert!(chunk_boundaries(&[], &config).is_empty());
        assert!(chunk_boundaries(&vec![0.1; 4 * SR], &config).is_empty());
    }

    #[test]
    fn cut_lands_in_the_silent_gap_before_the_nominal_boundary() {
        // Gap at 4.2s-4.4s: inside the 3.5s-5.0s search window.
        let audio = speech_with_gaps(7.0, &[4.2], 200);
        let boundaries = chunk_boundaries(&audio, &test_config());
        assert_eq!(boundaries.len(), 1);
        let cut = boundaries[0] as f32 / SR as f32;
        assert!(
            (4.2..4.4).contains(&cut),
            "cut at {cut}s, expected in the gap"
        );
    }

    #[test]
    fn a_short_stop_closure_loses_to_a_real_pause() {
        // A 40ms near-silent dip (the closure inside "dicta|tion") later in
        // the window than a 200ms pause between words: the cut must take the
        // pause, or it splits the word.
        let mut audio = speech_with_gaps(7.0, &[3.8], 200);
        let dip = (4.7 * SR as f32) as usize;
        audio[dip..dip + 40 * SR / 1000]
            .iter_mut()
            .for_each(|s| *s = 0.0);
        let cut = chunk_boundaries(&audio, &test_config())[0] as f32 / SR as f32;
        assert!(
            (3.8..4.0).contains(&cut),
            "cut at {cut}s, expected in the pause"
        );
    }

    #[test]
    fn a_gap_outside_the_window_is_not_used() {
        // Gap at 2.0s is before the search window (3.5s-5.0s).
        let audio = speech_with_gaps(7.0, &[2.0], 200);
        let cut = chunk_boundaries(&audio, &test_config())[0] as f32 / SR as f32;
        assert!((3.5..=5.0).contains(&cut), "cut at {cut}s");
    }

    #[test]
    fn chunks_are_contiguous_and_cover_the_audio_once() {
        let audio = speech_with_gaps(23.0, &[4.6, 9.1, 13.7, 18.0], 150);
        let boundaries = chunk_boundaries(&audio, &test_config());
        assert!(boundaries.len() >= 3);
        let mut expected_start = 0;
        for i in 0..boundaries.len() {
            let (start, end) = chunk_range(&boundaries, i).unwrap();
            assert_eq!(
                start,
                expected_start,
                "chunk {i} starts where {} ended",
                i.saturating_sub(1)
            );
            assert!(end > start);
            expected_start = end;
        }
        assert_eq!(tail_start(&boundaries, boundaries.len()), expected_start);
        assert!(chunk_range(&boundaries, boundaries.len()).is_none());
    }

    #[test]
    fn boundaries_are_stable_as_audio_grows() {
        // The daemon recomputes boundaries every poll; chunks already sent
        // must keep their bounds when more audio arrives.
        let audio = speech_with_gaps(30.0, &[4.3, 8.8, 12.1, 17.5, 21.9], 120);
        let config = test_config();
        let full = chunk_boundaries(&audio, &config);
        for len in (5 * SR..audio.len()).step_by(SR / 3) {
            let prefix = chunk_boundaries(&audio[..len], &config);
            assert_eq!(
                &full[..prefix.len()],
                &prefix[..],
                "prefix of {len} samples"
            );
        }
    }

    #[test]
    fn continuous_speech_still_cuts_inside_the_window() {
        let audio = speech_with_gaps(11.0, &[], 0);
        let boundaries = chunk_boundaries(&audio, &test_config());
        assert_eq!(boundaries.len(), 2);
        assert!((3 * SR + SR / 2..=5 * SR).contains(&boundaries[0]));
    }

    #[test]
    fn audio_that_fits_is_one_window() {
        let audio = speech_with_gaps(30.0, &[10.0], 200);
        assert_eq!(
            long_audio_windows(&audio, 30 * SR, 5 * SR),
            vec![(0, audio.len())]
        );
        assert_eq!(long_audio_windows(&[], 30 * SR, 5 * SR), vec![(0, 0)]);
    }

    #[test]
    fn long_audio_windows_are_contiguous_bounded_and_cover_everything() {
        // 10 minutes of continuous "speech", the case #288 hit.
        let audio = speech_with_gaps(600.0, &[], 0);
        let max = 60 * SR;
        let windows = long_audio_windows(&audio, max, 10 * SR);
        assert_eq!(windows.first().unwrap().0, 0);
        assert_eq!(windows.last().unwrap().1, audio.len());
        for pair in windows.windows(2) {
            assert_eq!(pair[0].1, pair[1].0, "windows must not overlap or gap");
        }
        for &(start, end) in &windows {
            assert!(end > start);
            assert!(end - start <= max, "window of {} samples", end - start);
        }
    }

    #[test]
    fn long_audio_cuts_land_in_pauses() {
        // 150s with pauses near where 3 even windows would end (50s, 100s).
        let audio = speech_with_gaps(150.0, &[46.0, 97.5], 300);
        let windows = long_audio_windows(&audio, 60 * SR, 10 * SR);
        assert_eq!(windows.len(), 3);
        let cut1 = windows[0].1 as f32 / SR as f32;
        let cut2 = windows[1].1 as f32 / SR as f32;
        assert!((46.0..46.3).contains(&cut1), "first cut at {cut1}s");
        assert!((97.5..97.8).contains(&cut2), "second cut at {cut2}s");
    }

    #[test]
    fn long_audio_never_leaves_a_sliver_at_the_end() {
        // Just over one window: split roughly in half, not 60s + 1s.
        let audio = speech_with_gaps(61.0, &[], 0);
        let windows = long_audio_windows(&audio, 60 * SR, 10 * SR);
        assert_eq!(windows.len(), 2);
        let last = windows[1].1 - windows[1].0;
        assert!(last >= 25 * SR, "last window is {}s", last / SR);
    }

    #[test]
    fn tail_starts_at_zero_without_chunks() {
        assert_eq!(tail_start(&[], 0), 0);
        assert_eq!(tail_start(&[70000, 150000], 1), 70000);
        assert_eq!(tail_start(&[70000, 150000], 2), 150000);
    }

    #[test]
    fn test_combine_chunk_results_empty() {
        assert_eq!(combine_chunk_results(vec![]), "");
    }

    #[test]
    fn test_combine_chunk_results_single() {
        assert_eq!(
            combine_chunk_results(vec![result("hello world", 0)]),
            "hello world"
        );
    }

    #[test]
    fn combine_joins_disjoint_chunks_in_order() {
        let results = vec![
            result("foo bar", 1),
            result("hello world", 0),
            result("baz", 2),
        ];
        assert_eq!(combine_chunk_results(results), "hello world foo bar baz");
    }

    #[test]
    fn combine_keeps_words_the_speaker_really_repeated() {
        // A word said twice across a boundary is two words, not a duplicate.
        let results = vec![result("I think that", 0), result("that is fine", 1)];
        assert_eq!(combine_chunk_results(results), "I think that that is fine");
        let results = vec![result("dictation.", 0), result("Dictation works.", 1)];
        assert_eq!(
            combine_chunk_results(results),
            "dictation. Dictation works."
        );
    }

    #[test]
    fn combine_skips_empty_chunks_without_double_spaces() {
        let results = vec![
            result(" one ", 0),
            result("", 1),
            result("  ", 2),
            result("two", 3),
        ];
        assert_eq!(combine_chunk_results(results), "one two");
    }

    fn joined(a: &str, b: &str) -> String {
        combine_chunk_results(vec![result(a, 0), result(b, 1)])
    }

    #[test]
    fn a_period_added_at_a_mid_sentence_cut_is_dropped() {
        // Seen in the rc2 smoke run: "chunk. boundaries".
        assert_eq!(
            joined("left no artifacts at the chunk.", "boundaries this time"),
            "left no artifacts at the chunk boundaries this time"
        );
    }

    #[test]
    fn sentence_casing_on_a_function_word_after_a_cut_is_lowered() {
        assert_eq!(
            joined("we moved everything to", "The new office"),
            "we moved everything to the new office"
        );
    }

    #[test]
    fn real_boundaries_and_names_are_left_alone() {
        let untouched = [
            ("It works.", "The next part starts here"),
            ("Did it work?", "yes it did"),
            ("Wow!", "that was fast"),
            ("Wait...", "no, go back"),
            ("I spoke to Mr.", "smith about it"),
            ("try something, e.g.", "this one"),
            ("and then", "I said no"),
            ("we flew to", "Paris on Monday"),
            ("paste the", "API key here"),
            ("I think that", "that is fine"),
        ];
        for (a, b) in untouched {
            assert_eq!(joined(a, b), format!("{a} {b}"), "{a:?} + {b:?}");
        }
    }
}
