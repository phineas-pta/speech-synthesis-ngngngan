## Part 3: prepare data for text-to-speech

discard 1 file 1h audio because bad organization/backup ⇒ **20 video files - 5h37min audio (1 speaker) at 48 kHz**

inspiration: https://viblo.asia/p/ong-toan-vi-loc-ung-dung-deep-learning-tu-dong-sinh-ra-series-audio-truyen-ma-sieu-to-khong-lo-bJzKmwqkl9N

the article above, dated from 2019, uses google API for speech recognition and train a LSTM model for text-to-speech

in this project, i’ll use more recent end-to-end models with transformers architecture, possible template: https://github.com/NTT123/light-speed

SOTA models at the time of writing:
- P-Flow TTS: https://github.com/p0p4k/pflowtts_pytorch (still seem unstable, got sudden crash)
- Matcha-TTS: https://github.com/shivammehta25/Matcha-TTS (seem easier to start)
- VITS 2: https://github.com/p0p4k/vits2_pytorch (seem easier to start)
- XTTS 2: https://github.com/coqui-ai/TTS/blob/dev/recipes/ljspeech/xtts_v2/train_gpt_xtts.py (don’t know how to add language)
- StyleTTS 2: https://github.com/yl4579/StyleTTS2 (config more complicated)
- VALL-E: https://github.com/Plachtaa/VALL-E-X (don’t know how to add language)
- VoiceFlow-TTS: https://github.com/X-LANCE/VoiceFlow-TTS (config more complicated)

### 6. transcribe

using `whisper`, then cut audio into segments
```
pip install openai-whisper
python scripts/06-transcribe-then-cut.py
```
audios saved in folder `data/06-subs`, convert from dual to mono channel, downsample from 48 kHz to 22 kHz

audio-text file-list save as `data/99-audio-text-file-list/_all.txt` ⇐ manually skim through to check for hallucination unnoticed

*lost 37’ audio because `whisper` hallucinate, eventhough already used SileroVAD*

### 7. phonemize

**this step is crucial as it replaces built-in english-only pre-processing scripts found in repo of SOTA models**

normalize, convert number to word, then phonemize to IPA

attempt to use other phonemizer but not work because IPA output incompatible:
- `from underthesea.pipeline.ipa import viet2ipa`: accurate but can only process word, not cover all vocab, silently throw empty string
- `from epitran import Epitran`: very fast but bad accuracy

⇒ must use `phonemizer` with `espeak` backend to be compatible with existing training scripts found in popular repo

install `espeak`: https://github.com/espeak-ng/espeak-ng/blob/master/docs/guide.md
```
pip install pandas underthesea phonemizer num2words
python scripts/07-phonemize.py
```
audio-text file-list save as `data/99-audio-text-file-list/_all_normal_ipa.txt`

### 8. split train-val-test

`python scripts/08-split-3sets.py`

6 audio-text file-list save to folder `data/99-audio-text-file-list`

excerpt of audio-text file-list:
```
# example from _all.txt
rZnygcVV3vI_0002.wav|Họ thay đổi nội dung cốt truyện, thay đổi tốc độ và thậm chí sửa cả tựa của câu truyện,

# example from ███_filelist.txt (3 files train-val-test)
../speech-synthesis-ngngngan/data/06-subs/rZnygcVV3vI_0002.wav|Họ thay đổi nội dung cốt truyện, thay đổi tốc độ và thậm chí sửa cả tựa của câu truyện,

# example from ███_filelist.txt.cleaned (3 files train-val-test)
../speech-synthesis-ngngngan/data/06-subs/rZnygcVV3vI_0002.wav|hˈɔ6 tˈaj ɗˈo4j nˈo6j zˈuŋ kˈoɜt̪ t͡ʃwˈi͡ɛ6n, tˈaj ɗˈo4j t̪ˈoɜk ɗˈo6 vˌaː2 tˈə6m t͡ʃˈiɜ sˈy͡ə4 kˈaː4 t̪ˈy͡ə6 kˌu͡ə4 kˈə1w t͡ʃwˈi͡ɛ6n,
```
