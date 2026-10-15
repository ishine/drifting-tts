# ARDrift in English: 10,000 hours of synthetic speech

ARDrift ([docs/AR_DRIFT.md](AR_DRIFT.md)) trained in English from scratch, with an English character frontend, on 10,000
hours of synthetic speech too large for the disk, so streamed from the Hub while training.

- [Data](#data)
- [What changed in the code](#what-changed-in-the-code)
- [Results](#results)
- [Limits](#limits)
- [Commands](#commands)

## Data

[VoiceHub/echo-clones-10kh-en](https://huggingface.co/datasets/VoiceHub/echo-clones-10kh-en): the first 6,949 parquet
shards, unchanged, of [SynDataLab-EN/echo-clones-4m-en](https://huggingface.co/datasets/SynDataLab-EN/echo-clones-4m-en):

| | |
|---|---|
| hours / utterances | 10,000.7 h / 3,474,250 (1.33 TB) |
| speech | synthetic, generated with [EchoTTS (jordand/echo-tts-base)](https://huggingface.co/jordand/echo-tts-base) for 4,000 reference speakers, 44.1 kHz |
| text | conversational English, 24-420 characters (fillers, em dashes, few digits or acronyms) |
| license | Apache-2.0 as declared by the source; the generating model is CC-BY-NC-SA-4.0 |

The source's shards are not uniform: the first ones hold mid-length utterances (median 8.3 s in shards 0-69), later
ones many short ones (median 5.6 s in shard 3,000).

**Held out:** the val and dev splits (200 + 300 utterances) come from source shard 07,960, which is not among the
6,949 shards: texts never trained on, read by the training speakers (every speaker occurs throughout the corpus).

## What changed in the code

- **English frontend** (`drifting_tts/text_en.py`): the 26 letters, the apostrophe (`we'll`, `don't`: it changes the
  pronunciation) and the Turkish frontend's punctuation, with `<pad>` / `<blank>` at the same ids. Normalisation
  writes out numbers, years (`1999` → *nineteen ninety nine*), decades, ordinals, money, percentages, clock times,
  common abbreviations and all-caps acronyms letter by letter (`TV` → *tee vee*, while emphasis like `SO` stays a word).
  English spelling is far from phonemic; with this much data the text encoder learns the letters' sounds (no G2P).
- **A language switch**: `model.text.language` sets the text encoder's vocabulary and a prepared dataset's
  `stats.json` records its language (`prepare --language`); the Synthesizer, `evaluate` and Whisper follow them. A
  model or dataset without a language is Turkish, as before.
- **`prepare`**: `--speaker-column`, `--val-glob` (held-out files form the val split, the rest of them dev), and
  `hf://` paths read without a local copy.
- **Streaming** (`drifting_tts/stream.py`, `data.stream`): 10,000 h of log-mels would take ~675 GB. Each DataLoader
  worker downloads every n-th shard of a shuffled order (the next one while it reads the current one), turns each row
  into a log-mel as `prepare` does and yields length-bucketed batches; at most two shards per worker are on disk. One
  core makes mels ~1,400x faster than real time, so the network decides: 12 workers deliver ~2,165 s of audio per
  second, more than the training uses. The mel statistics, the speaker table and the val split come from the
  prepared pilot data.
- `evaluate --asr-device cpu`: Whisper beside a training run that holds the GPU.

## Results

Val 100 (the first 100 held-out utterances): Whisper large-v3 in English (for the 10k-h run on the CPU, int8),
UTMOSv2, WavLM-ECAPA similarity to the recording's copy-synthesis; Vocos v2, noise temperature 0.5, no guidance. The
copy-synthesis row is the recording's mel through Vocos v2: the ceiling of this vocoder.

**Pilot** (`configs/ar_tts_en.yaml`: 87.7 h, source shards 0-69; the Turkish model's size with a wider text encoder:
12.8 + 42.5 + 18.0 M; 30k steps, 7.2 it/s):

| step | WER | CER | UTMOSv2 | SIM |
|---|---|---|---|---|
| 10k | 22.82% | 12.61% | 2.742 | 0.190 |
| 20k | 4.74% | 2.39% | 2.912 | 0.329 |
| 30k | 3.32% | 1.52% | 2.957 | 0.422 |
| copy-synthesis | 2.57% | 1.12% | 2.926 | – |

**10,000 h** (`configs/ar_tts_en_10k.yaml`: 36.2 + 121.2 + 20.5 M, batches of up to 48 utterances, 200k steps, about
one pass over the data, 13 h on one RTX 5090):

| step | WER | CER | UTMOSv2 | SIM |
|---|---|---|---|---|
| 20k | 3.99% | 2.04% | 2.917 | 0.394 |
| 40k | 2.51% | 1.22% | 2.950 | 0.591 |
| 60k | 2.51% | 1.26% | 3.014 | 0.653 |
| 80k | 2.30% | 1.03% | 2.907 | 0.695 |
| 100k | 2.17% | 0.94% | 2.945 | 0.722 |
| 120k | 2.51% | 1.07% | 2.990 | 0.740 |
| 140k | 2.10% | 0.98% | 2.904 | 0.757 |
| 160k | 2.57% | 1.07% | 2.998 | 0.771 |
| 180k | 2.10% | 0.92% | 2.949 | 0.770 |
| 200k | 2.17% | 0.90% | 2.994 | 0.774 |
| copy-synthesis | 2.44% | 1.09% | 2.926 | – |

**All 500 held-out utterances** (val 200 + dev 300, 15,302 words; Whisper on the GPU, fp16), to tell the last
snapshots apart:

| step | WER | CER | UTMOSv2 | SIM |
|---|---|---|---|---|
| 140k | 1.50% | 0.65% | 2.916 | 0.783 |
| 180k | **1.39%** | **0.62%** | 2.921 | 0.800 |
| **200k** (the model in the test Space) | 1.42% | 0.64% | **2.930** | **0.803** |
| copy-synthesis | 1.57% | 0.73% | 2.907 | – |

180k and 200k differ by 5 words; 200k is ahead on similarity and UTMOSv2. The test Space holds the 200k weights in fp16 (`export_tts(half=True)`: 356
MB, a Space stores at most 1 GB): on val 100 the same WER / CER as fp32 (2.23% / 0.90%), UTMOSv2 3.002 against 2.994.

- **As intelligible as the recordings from 40k steps on**, with the vocoder they go through, and slightly more on
  all 500 utterances (1.42% against 1.57%: the source's own slips are not learned); the 100 utterances hold ~1,500
  words, so the snapshots after 40k differ there by a few words.
- **The voices are what more data buys**: similarity to each speaker rises at every snapshot, 0.39 → 0.77, where the
  pilot, with ~9 utterances per speaker, stopped at 0.42.
- **UTMOSv2 at the recordings' level** (2.90-3.01 against 2.926): the synthetic source is the ceiling.

## Vocoder: BigVGAN-v2 fine-tuned on the model's mels (#70)

Vocos v2, the vocoder of the tables above, was trained on Turkish speech. On the English recordings' mels it loses
0.33 UTMOSv2 (val 100: 2.926 against the recordings' 3.259). NVIDIA's BigVGAN-v2 is transparent on those mels
(3.296), but on the model's mels it falls to 2.680, against Vocos v2's 2.997. Both vocoders were fine-tuned on the
200k model's own mels (GTA: 80% of the batches are teacher-forced generated mels at noise temperature 0.5, the rest
recorded mels), 40k steps each, side by side on one RTX 5090. The data is the 37,115 utterances (105 h train) of the
Mimi decoder fine-tune ([MIMI.md](MIMI.md#fine-tuning-mimis-decoder)): the same prepared audio, as BigVGAN log-mels
(`data/en_mel_ft`).

- **BigVGAN-v2** (`configs/vocoder_bigvgan_en_gta.yaml`): the recipe of `bigvgan-v2-ft`, i.e. NVIDIA's generator,
  discriminators and AdamW moments, batch 4, lr 1.35e-5; 1.9-2.4 it/s, 5.4 h.
- **Vocos v2** (`configs/vocoder_vocos_en_gta.yaml`): Vocos v2's own recipe, from the published generator
  (`train.init_from: vocos-v2`: an exported vocoder gives the generator only). Its discriminators were not
  published, so fresh ones train alone for the first 2k steps.

Val 100, the model's output through each snapshot (Whisper on the CPU, as the tables above; Vocos v2: 2.17% / 2.994):

| step | BigVGAN-v2 WER | UTMOSv2 | Vocos v2 WER | UTMOSv2 |
|---|---|---|---|---|
| 5k | 2.10% | 3.165 | 2.30% | 2.927 |
| 10k | 2.10% | 3.165 | 2.03% | 2.949 |
| 15k | 2.17% | 3.207 | 2.10% | 2.985 |
| 20k | 2.03% | 3.163 | 2.10% | 3.001 |
| 25k | 2.03% | 3.197 | 2.10% | 2.981 |
| 30k | 2.10% | 3.217 | 1.90% | 2.998 |
| 35k | 2.17% | 3.178 | 2.03% | 3.025 |
| 40k | 2.37% | **3.272** | 1.90% | 3.043 |

The two best BigVGAN snapshots on all 500 held-out utterances (Whisper on the GPU, as the 500-utterance table
above); copy-synthesis is the recordings' mels through the same vocoder:

| vocoder | WER | CER | UTMOSv2 | copy-synthesis WER | UTMOSv2 |
|---|---|---|---|---|---|
| Vocos v2 | 1.42% | 0.64% | 2.930 | 1.57% | 2.907 |
| BigVGAN-v2 GTA 30k | 1.38% | 0.62% | 3.177 | 1.57% | 3.276 |
| **BigVGAN-v2 GTA 40k** | **1.35%** | **0.60%** | **3.245** | 1.57% | 3.294 |

Against Vocos v2, sentence by sentence (the same mels): UTMOSv2 +0.315 ± 0.025 (95%), higher on 436 of 500; 10
word errors fewer. Speaker similarity is left out: its reference is the copy-synthesis through the same vocoder.

Where the noise is, on val 100 (DNSMOS P.835: SIG speech, BAK background, OVRL overall; noise floor: the 10th
percentile of the 20 ms frame energies minus the 95th, lower is quieter):

| | UTMOSv2 | SIG | BAK | OVRL | noise floor |
|---|---|---|---|---|---|
| recording | 3.259 | 3.53 | 4.12 | 3.29 | −57.3 dB |
| copy-synthesis, Vocos v2 | 2.926 | 3.49 | 4.11 | 3.25 | −60.8 dB |
| copy-synthesis, BigVGAN-v2 GTA 40k | 3.314 | 3.55 | 4.13 | 3.31 | −57.5 dB |
| model, Vocos v2 | 2.997 | 3.48 | 4.07 | 3.21 | −52.2 dB |
| model, BigVGAN-v2 GTA 40k | 3.280 | 3.52 | 4.07 | 3.26 | −50.9 dB |

- **The vocoder gap is closed**: the model's output through the fine-tuned BigVGAN scores close to the recordings
  through it (3.245 against 3.294 on 500), and higher than the recordings through Vocos v2.
- **The model's higher noise floor is shorter pauses, not noise** (see [Pauses](#pauses-the-duration-predictor-re-fitted-to-the-mean-72)):
  the percentile floor rises when an utterance has less silence. Under the recordings' durations the model's pauses
  are as quiet as theirs.
- **Vocos v2 gains little** (+0.05 at 40k, its copy-synthesis 2.93 → 3.10): too small a network, or the fresh
  discriminators.
- **Cost**: 112 M parameters against 13.5 M. On the RTX 5090 the whole pipeline's real-time factor goes from 0.14 to
  0.16.
- **Where**: a private English Space of its own offers it as the default, next to Vocos v2 (`space_en/`,
  `scripts/deploy_english_space.sh`; fp16 weights, 225 MB). The test Space has no room left: a Space stores at most
  1 GB, every stored file version included. Its English tab keeps Vocos v2. The vocoder is not on the Hub and not in
  the vocoder registry.

## Pauses: the duration predictor re-fitted to the mean (#72)

#72 planned a discriminator against the pause noise of the table above. The measurement came first (val 100 or 200,
BigVGAN-v2 GTA 40k, T 0.5, mel-domain frame energies), and the noise is not there:

- **Under the recordings' own durations (MAS), the model's pauses are as quiet as the recordings'.** Mel noise floor:
  −59.3 dB teacher-forced and −59.0 dB free-running, against −59.0 dB.
- **With its predicted durations, an utterance holds less silence, not louder silence.**
  - The floor rises to −53.3 dB.
  - 18% of the frames are more than 40 dB below the loudest, against 34% in the recordings.
  - The 20 quietest frames are at −72.3 dB, against −74.0 dB.
  - A percentile floor measures how much of an utterance is silent.
- **The missing silence is at punctuation.** UTMOSv2 does not hear it: the model scores 3.316, its copy-synthesis
  3.314.
- **Nothing for a discriminator to learn**, so #72 changed course.

**The cause.** The duration predictor regresses log-durations (`duration_loss`), so it learns the geometric mean. A
comma is read with no pause by one speaker and a long one by the next, and the geometric mean of such a spread is a
fraction of its mean. Letters vary little, so for them the two means agree.

**The fix.** `drifting-tts train-durations` trains only the duration predictor (0.54 M parameters, the rest frozen)
on the model's own MAS durations. It uses a Poisson loss, minimised at the mean, on the duration minus half a frame:
synthesis rounds every duration up, which adds half a frame on average. Without that offset the ~150 tokens of a
sentence came out 0.8 s long. 4,000 steps on `data/en_pilot`, 3 minutes on the RTX 5090.

Seconds per val utterance (200), by where the tokens are:

| | punctuation | word gaps | letters | edges | total |
|---|---|---|---|---|---|
| recording (MAS) | 1.19 | 0.29 | 4.29 | 0.13 | 5.90 |
| regressor (log-durations) | 0.45 | 0.32 | 4.13 | 0.13 | 5.04 |
| **re-fitted (Poisson)** | **1.09** | **0.29** | **4.15** | 0.14 | **5.66** |

On the 500 held-out utterances (BigVGAN-v2 GTA 40k, as above):

| durations | WER | CER | UTMOSv2 | similarity |
|---|---|---|---|---|
| regressor | 1.35% | 0.60% | 3.245 | 0.824 |
| **re-fitted** | 1.39% | 0.61% | 3.236 | **0.846** |

- **Intelligibility and naturalness are unchanged**: 212 word errors against 207 of 15,302 words. UTMOSv2 differs by
  −0.008 sentence by sentence (95%: −0.034 to +0.017).
- **Closer to the speaker**: similarity +0.022 (95%: +0.019 to +0.025), higher on 398 of 500 sentences. Both rows use
  the same vocoder, so the copy-synthesis reference is the same.
- **Where**: the private English Space offers both and defaults to the re-fitted one. It holds only the predictor
  (`durations_en.pt`, 2.2 MB, `drifting_tts.publish.export_durations`), since the Space stores at most 1 GB.

## Limits

- **Synthetic data**: the model learns EchoTTS's voices and its artefacts; a recorded corpus would be needed to go past
  them.
- **License**: the generating model's CC-BY-NC-SA-4.0 may restrict commercial use of a model trained on this data.
- **Speakers by ID only** (4,000 table rows), no cloning from a reference recording.
- **The test set is from the same synthetic corpus**: texts never seen, voices seen. There is no comparison with
  other English TTS systems on a common benchmark yet.

## Commands

```bash
# pilot data (also the mel statistics, speaker table and val split of the 10k-h run)
drifting-tts prepare --parquet-glob "hf://datasets/SynDataLab-EN/echo-clones-4m-en/data/train-000[0-6][0-9].parquet" \
    --val-glob "hf://datasets/SynDataLab-EN/echo-clones-4m-en/data/train-07960.parquet" --val-size 200 \
    --out data/en_pilot --backend bigvgan --language en --speaker-column speaker_id --workers 24
drifting-tts train-ar --config configs/ar_tts_en.yaml --workdir runs/ar_en_pilot
drifting-tts train-ar --config configs/ar_tts_en_10k.yaml --workdir runs/ar_en_10k     # streamed from the Hub
drifting-tts evaluate --model runs/ar_en_10k/model_ema.pt --split val --num 100 --temperature 0.5 --vocoder vocos-v2
# vocoder (#70): data/en_mel_ft = data/en_mimi_ft's utterances and audio.bin, with BigVGAN log-mels of that audio
drifting-tts finetune-vocoder --config configs/vocoder_bigvgan_en_gta.yaml --workdir runs/en_bigvgan_gta
drifting-tts evaluate --model runs/ar_en_10k/model_ema.pt --split val --num 100 --temperature 0.5 \
    --vocoder runs/en_bigvgan_gta/bigvgan_ft_40000.pt
# pauses (#72): the duration predictor re-fitted to the mean duration, the rest of the model unchanged
drifting-tts train-durations --model runs/ar_en_10k/model_ema.pt --out runs/en_dur/model_poisson.pt
```

```python
tts = Synthesizer("runs/ar_en_10k/model_ema.pt", "cuda", vocoder="vocos-v2")
wav, _ = tts("Hello! It's 7:45, and the 90s called.", speaker="spk_0042", temperature=0.5)
```
