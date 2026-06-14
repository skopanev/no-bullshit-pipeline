use anyhow::Result;
use log::warn;

/// True peak limiter with lookahead buffer (prevents clipping)
struct TruePeakLimiter {
    lookahead_samples: usize,
    buffer: Vec<f32>,
    gain_reduction: Vec<f32>,
    current_position: usize,
}

impl TruePeakLimiter {
    fn new(sample_rate: u32) -> Self {
        const LIMITER_LOOKAHEAD_MS: usize = 10;
        let lookahead_samples = ((sample_rate as usize * LIMITER_LOOKAHEAD_MS) / 1000).max(1);

        Self {
            lookahead_samples,
            buffer: vec![0.0; lookahead_samples],
            gain_reduction: vec![1.0; lookahead_samples],
            current_position: 0,
        }
    }

    fn process(&mut self, sample: f32, true_peak_limit: f32) -> f32 {
        self.buffer[self.current_position] = sample;

        let sample_abs = sample.abs();
        if sample_abs > true_peak_limit {
            let reduction = true_peak_limit / sample_abs;
            self.gain_reduction[self.current_position] = reduction;
        } else {
            self.gain_reduction[self.current_position] = 1.0;
        }

        let output_position = (self.current_position + 1) % self.lookahead_samples;
        let output_sample = self.buffer[output_position] * self.gain_reduction[output_position];

        self.current_position = output_position;
        output_sample
    }
}

/// Professional loudness normalizer using EBU R128 standard
/// This is a STATEFUL normalizer that tracks cumulative loudness over time
pub struct LoudnessNormalizer {
    ebur128: ebur128::EbuR128,
    limiter: TruePeakLimiter,
    gain_linear: f32,
    loudness_buffer: Vec<f32>,
    true_peak_limit: f32,
}

impl LoudnessNormalizer {
    /// Create a new EBU R128 loudness normalizer
    pub fn new(channels: u32, sample_rate: u32) -> Result<Self> {
        const TRUE_PEAK_LIMIT: f64 = -1.0;
        const ANALYZE_CHUNK_SIZE: usize = 512;

        let ebur128 = ebur128::EbuR128::new(
            channels,
            sample_rate,
            ebur128::Mode::S | ebur128::Mode::TRUE_PEAK,
        )
        .map_err(|e| anyhow::anyhow!("Failed to create EBU R128 normalizer: {}", e))?;

        let true_peak_limit = 10_f32.powf(TRUE_PEAK_LIMIT as f32 / 20.0);

        Ok(Self {
            ebur128,
            limiter: TruePeakLimiter::new(sample_rate),
            gain_linear: 1.0,
            loudness_buffer: Vec::with_capacity(ANALYZE_CHUNK_SIZE),
            true_peak_limit,
        })
    }

    /// Normalize loudness using EBU R128 standard with true peak limiting
    /// Target: -23 LUFS
    pub fn normalize_loudness(&mut self, samples: &[f32]) -> Vec<f32> {
        if samples.is_empty() {
            return Vec::new();
        }

        const TARGET_LUFS: f64 = -23.0;
        const ANALYZE_CHUNK_SIZE: usize = 512;
        // Below this short-term loudness the signal is effectively silence.
        // Chasing the target here cranks makeup gain to +40..+50 dB, which then
        // brick-walls the next words into a square wave (the source of the
        // crackle and a chunk of the diarization fragmentation). Hold instead.
        const SILENCE_GATE_LUFS: f64 = -40.0;
        // Cap makeup/attenuation as a backstop. The silence gate above is what
        // actually prevents the noise-floor explosion, so this can stay generous:
        // a quiet mic legitimately needs ~+15..+18 dB to reach -23 LUFS and match
        // a hot source (e.g. FaceTime system audio). +12 dB was starving it.
        const MAX_GAIN_DB: f64 = 20.0;
        // Ease toward the target each 512-sample update (~10 ms) to avoid steps.
        const GAIN_SMOOTHING: f32 = 0.15;

        let mut normalized_samples = Vec::with_capacity(samples.len());

        for &sample in samples {
            // Accumulate samples for loudness analysis
            self.loudness_buffer.push(sample);

            // Analyze loudness every 512 samples
            if self.loudness_buffer.len() >= ANALYZE_CHUNK_SIZE {
                if let Err(e) = self.ebur128.add_frames_f32(&self.loudness_buffer) {
                    warn!("Failed to add frames to EBU R128: {}", e);
                } else {
                    // Update gain based on cumulative loudness. Only adapt while
                    // there is real signal, cap the makeup gain, and ease toward
                    // the target so the encoder never sees a saturated waveform.
                    if let Ok(current_lufs) = self.ebur128.loudness_shortterm()
                        && current_lufs.is_finite()
                        && (SILENCE_GATE_LUFS..0.0).contains(&current_lufs)
                    {
                        let gain_db = (TARGET_LUFS - current_lufs).clamp(-MAX_GAIN_DB, MAX_GAIN_DB);
                        let target_gain = 10_f32.powf(gain_db as f32 / 20.0);
                        self.gain_linear += (target_gain - self.gain_linear) * GAIN_SMOOTHING;
                    }
                }
                self.loudness_buffer.clear();
            }

            // Apply gain and true peak limiting
            let amplified = sample * self.gain_linear;
            let limited = self.limiter.process(amplified, self.true_peak_limit);

            normalized_samples.push(limited);
        }

        normalized_samples
    }
}
