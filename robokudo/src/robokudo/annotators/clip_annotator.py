from __future__ import annotations

from dataclasses import dataclass, field

import faiss
import numpy as np
import torch
from PIL import Image
from transformers import CLIPModel, CLIPProcessor
from typing_extensions import TYPE_CHECKING, Any

from robokudo.annotators.zero_shot_classification_annotator import (
    ZeroShotClassificationAnnotator,
)
from robokudo.types.annotation import Classification

if TYPE_CHECKING:
    import numpy.typing as npt


@dataclass(kw_only=True)
class CLIPAnnotator(ZeroShotClassificationAnnotator):
    """
    Zero-shot classification by the similarity of CLIP's image embedding to the CLIP
    text embedding of each vocabulary entry.
    """

    device: torch.device = field(
        default_factory=lambda: torch.device(
            "cuda:0" if torch.cuda.is_available() else "cpu"
        )
    )
    """
    Torch device the model runs on.
    """

    model_name: str = "openai/clip-vit-large-patch14"
    """
    Name of the pretrained CLIP model.
    """

    vocabulary_template: str = "A photo of a {}"
    """
    A template string that each vocabulary word is inserted into.
    """

    use_softmax: bool = True
    """
    Whether to apply softmax to the results of the analyzed image or hypothesis or not.
    """

    clip_model: CLIPModel = field(init=False, repr=False)
    """
    CLIP model used for feature extraction, loaded in :meth:`setup`.
    """

    clip_preprocess: CLIPProcessor = field(init=False, repr=False)
    """
    CLIP preprocessor used for input preprocessing, loaded in :meth:`setup`.
    """

    vocabulary_index: faiss.IndexFlatIP = field(init=False, repr=False)
    """
    Index of the normalized text features of the vocabulary, built in :meth:`setup`.
    """

    def setup(self, **kwargs: Any) -> bool:
        """
        Load the CLIP model and index the text features of the vocabulary.
        """
        self.clip_model = CLIPModel.from_pretrained(self.model_name).to(self.device)
        self.clip_preprocess = CLIPProcessor.from_pretrained(self.model_name)
        self.vocabulary_index = faiss.IndexFlatIP(self.clip_model.config.projection_dim)
        with torch.no_grad():
            templated_texts = [
                self.vocabulary_template.format(word) for word in self.vocabulary
            ]
            inputs = self.clip_preprocess.tokenizer(
                templated_texts,
                padding=True,
                return_tensors="pt",
            ).to(self.device)
            text_features = self.clip_model.get_text_features(**inputs).pooler_output
            text_features /= torch.norm(text_features, p=2, dim=-1, keepdim=True)
            text_features = text_features.cpu().numpy()
        self.vocabulary_index.add(text_features)
        return super().setup(**kwargs)

    def _get_image_features(self, images: list[Image.Image]) -> npt.NDArray[np.float32]:
        """
        Get normalized image features for the given images.

        :param images: The images to get features from.
        :return: The features of each image.
        """
        with torch.inference_mode():
            inputs = self.clip_preprocess(images=images, return_tensors="pt").to(
                self.clip_model.device
            )
            crop_features = self.clip_model.get_image_features(**inputs).pooler_output
            crop_features /= torch.norm(crop_features, p=2, dim=-1, keepdim=True)
            crop_features = crop_features.cpu().numpy()
        return crop_features

    def _candidate_count(self) -> int:
        """
        Number of vocabulary entries to retrieve from the index per analyzed image.

        With softmax, every entry is needed to normalize the confidences; without it,
        only the kept ones, but never more than the vocabulary holds.
        """
        vocabulary_size = len(self.vocabulary)
        if self.use_softmax:
            return vocabulary_size
        return min(self.save_top_k, vocabulary_size)

    def _search_index(
        self,
        features: npt.NDArray[np.float32],
        k: int,
        use_softmax: bool,
        save_top_k: int,
    ) -> tuple[npt.NDArray[np.float32], npt.NDArray[np.int64]]:
        """
        Search the faiss index using the given features.

        :param features: The features to search the index with.
        :param k: The number of candidates to retrieve from the index for each feature.
        :param use_softmax: Whether to apply a softmax to the results of each feature.
        :param save_top_k: How many results to keep after applying softmax.
        :return: A tuple of (similarities, class indices)
        """
        class_similarities, class_indices = self.vocabulary_index.search(features, k=k)

        if use_softmax:
            logit_scale = self.clip_model.logit_scale.exp().item()
            logits = class_similarities * logit_scale

            class_similarities = torch.softmax(torch.tensor(logits), dim=1).numpy()

            class_similarities = class_similarities[:, :save_top_k]
            class_indices = class_indices[:, :save_top_k]
        else:
            # Move [-1.0, 1.0] to [0.0, 1.0]
            class_similarities += 1.0
            class_similarities /= 2.0

        return class_similarities, class_indices

    def classify(self, images: list[Image.Image]) -> list[list[Classification]]:
        class_similarities, class_indices = self._search_index(
            features=self._get_image_features(images),
            k=self._candidate_count(),
            use_softmax=self.use_softmax,
            save_top_k=self.save_top_k,
        )
        return [
            [
                Classification(
                    source=self.name,
                    classname=self.vocabulary[index],
                    confidence=similarity,
                )
                for index, similarity in zip(image_indices, image_similarities)
            ]
            for image_indices, image_similarities in zip(
                class_indices, class_similarities
            )
        ]
