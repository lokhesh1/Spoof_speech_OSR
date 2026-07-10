# Adapted from https://github.com/piotrkawa/audio-deepfake-source-tracing

import glob
import os
import random

import librosa
import numpy
import torch
import transformers
from scipy import signal


class HuggingFaceFeatureExtractor:
    def __init__(self, model_class_name, layer=-1, name=None):
        self.device = "cuda" if torch.cuda.is_available() else "cpu"
        self.feature_extractor = transformers.AutoFeatureExtractor.from_pretrained(name)
        model_class = getattr(transformers, model_class_name)

        self.model = model_class.from_pretrained(name, output_hidden_states=True)
        self.model.eval()
        self.model.to(self.device)
        self.layer = layer

    def __call__(self, audio, sr):
        if isinstance(audio, torch.Tensor):
            audio_cpu = audio.detach().cpu()
            if audio_cpu.dim() == 2:
                audio_input = [row.numpy() for row in audio_cpu]
            else:
                audio_input = audio_cpu.numpy()
        else:
            audio_input = audio

        inputs = self.feature_extractor(
            audio_input,
            sampling_rate=sr,
            return_tensors="pt",
            padding=True,
            return_attention_mask=True,
        )
        inputs = {k: v.to(self.device) for k, v in inputs.items()}
        # Squeeze for models that use input_values (W2V2, HuBERT)
        if "input_values" in inputs:
            inputs["input_values"] = inputs["input_values"].squeeze(0)
        # Whisper uses input_features instead
        if "input_features" in inputs:
            inputs["input_features"] = inputs["input_features"].squeeze(0)
        with torch.no_grad():
            outputs = self.model(**inputs)
        # Whisper encoder-decoder: use encoder hidden states
        if hasattr(outputs, "encoder_hidden_states") and outputs.encoder_hidden_states is not None:
            return outputs.encoder_hidden_states[self.layer]
        return outputs.hidden_states[self.layer]


class WaveformEmphasiser:
    def __init__(self, sampling_rate, musan_path, rir_path, segmented=False):
        self.sampling_rate = sampling_rate
        self.noisesnr = {"noise": [0, 15], "speech": [13, 20], "music": [5, 15]}
        self.numnoise = {"noise": [1, 1], "speech": [3, 8], "music": [1, 1]}
        self.noiselist = {}
        self.rir_files = glob.glob(os.path.join(rir_path, "*/*/*/*.wav"))
        self.segmented_audio = segmented

        self.augment_files = glob.glob(os.path.join(musan_path, "*/*/*.wav"))
        ## group the noises by category
        for file in self.augment_files:
            if file.split("/")[-3] not in self.noiselist:
                self.noiselist[file.split("/")[-3]] = []
            self.noiselist[file.split("/")[-3]].append(file)

    def __call__(self, waveform, emphasis="original"):
        waveform = self._unpack(waveform)
        if emphasis == "original":
            waveform = waveform
        elif emphasis == "reverb":
            waveform = self.add_reverb(waveform)
        elif emphasis in ["speech", "music", "noise"]:
            waveform = self.add_noise(waveform, emphasis)

        return self._pack(waveform)

    def _unpack(self, waveform):
        return waveform.squeeze().cpu().numpy()

    def _pack(self, waveform):
        return torch.Tensor(waveform)

    def add_reverb(self, audio):
        rir_file = random.choice(self.rir_files)
        rir, sr = librosa.load(rir_file, sr=self.sampling_rate)
        rir = rir / numpy.sqrt(numpy.sum(rir**2))
        if self.segmented_audio:
            # rir = numpy.tile(rir, (audio.shape[0], 1))
            # result = signal.convolve(audio, rir, mode="full")[:, :audio.shape[1]]
            result = signal.fftconvolve(audio, rir[None, :], mode="full")[:, : audio.shape[1]]
        else:
            result = signal.convolve(audio, rir, mode="full")[: audio.shape[0]]
        return result

    def add_noise(self, audio, noise_type="speech"):
        noise_file = random.choice(self.noiselist[noise_type])
        noise, sr = librosa.load(noise_file, sr=self.sampling_rate)

        if self.segmented_audio:
            audio_db = 10 * numpy.log10(
                numpy.mean(audio**2, axis=1, keepdims=True) + 1e-4
            )  # Compute audio dB for all channels

            if noise.shape[0] <= audio.shape[1]:
                noise = numpy.pad(noise, (0, audio.shape[1] - noise.shape[0]), "wrap")
            else:
                noise = noise[: audio.shape[1]]

            noise = numpy.tile(noise, (audio.shape[0], 1))  # Duplicate noise for all channels
            noise_db = 10 * numpy.log10(
                numpy.mean(noise**2, axis=1, keepdims=True) + 1e-4
            )  # Compute noise dB for all channels

            # Generate random SNR for each channel
            random_noise_snr = numpy.random.uniform(
                self.noisesnr[noise_type][0],
                self.noisesnr[noise_type][1],
                size=(audio.shape[0], 1),
            )

        else:
            # Single-channel processing (original code)
            audio_db = 10 * numpy.log10(numpy.mean(audio**2) + 1e-4)

            if noise.shape[0] <= audio.shape[0]:
                noise = numpy.pad(noise, (0, audio.shape[0] - noise.shape[0]), "wrap")
            else:
                noise = noise[: audio.shape[0]]
            noise_db = 10 * numpy.log10(numpy.mean(noise**2) + 1e-4)
            random_noise_snr = random.uniform(
                self.noisesnr[noise_type][0], self.noisesnr[noise_type][1]
            )

        noise = numpy.sqrt(10 ** ((audio_db - noise_db - random_noise_snr) / 10)) * noise

        result = audio + noise
        return result


def shuffle(feat: torch.Tensor, labels: torch.Tensor) -> tuple[torch.Tensor, torch.Tensor]:
    shuffle_index = torch.randperm(labels.shape[0])
    feat = feat[shuffle_index]
    labels = labels[shuffle_index]
    return feat, labels
