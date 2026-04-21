"""
<<<<<<< HEAD
KAVACH-AI Multimodal Fusion
=======
Multimodal Deepfake Detection System Using Advanced Machine Learning Techniques Multimodal Fusion
>>>>>>> 7df14d1 (UI enhanced)
Combines video and audio detection for robust deepfake detection
NO API KEYS REQUIRED - All processing is local
"""

import numpy as np
from typing import Dict, Optional, Tuple
from dataclasses import dataclass
from loguru import logger

from backend.features.temporal_analysis import TemporalFeatures


@dataclass
class MultimodalConfidence:
    """Multimodal fusion result"""
    # Individual modality scores
    spatial_confidence: float
    temporal_confidence: Optional[float]
    audio_confidence: Optional[float]
    
    # Fusion scores
    video_confidence: float        # Spatial + Temporal fusion
    final_confidence: float        # All modalities fused
    
    # Synchronization metrics
    av_sync_score: Optional[float] = None  # Audio-visual sync
    
    # Uncertainty
    uncertainty: float = 0.0
    
    # Metadata
    fusion_method: str = "weighted_average"


class MultimodalFusion:
    """
    Multimodal fusion engine for combining video and audio detection.
    
    Fusion strategies:
    1. Weighted averaging (simple, effective)
    2. Attention-based weighting (adaptive to modality reliability)
    3. Uncertainty-aware fusion (considers prediction confidence)
    """
    
    def __init__(
        self,
        spatial_weight: float = 0.5,
        temporal_weight: float = 0.2,
        audio_weight: float = 0.3
    ):
        """
        Initialize multimodal fusion.
        
        Args:
            spatial_weight: Weight for spatial detection
            temporal_weight: Weight for temporal detection
            audio_weight: Weight for audio detection
        """
        # Normalize weights to sum to 1
        total = spatial_weight + temporal_weight + audio_weight
        self.spatial_weight = spatial_weight / total
        self.temporal_weight = temporal_weight / total
        self.audio_weight = audio_weight / total
        
        logger.info(
            f"Multimodal fusion initialized "
            f"(spatial: {self.spatial_weight:.2f}, "
            f"temporal: {self.temporal_weight:.2f}, "
            f"audio: {self.audio_weight:.2f})"
        )
    
    def fuse(
        self,
        spatial_conf: float,
        temporal_conf: Optional[float] = None,
        audio_conf: Optional[float] = None,
        temporal_features: Optional[TemporalFeatures] = None,
        audio_features: Optional[Dict] = None
    ) -> MultimodalConfidence:
        """
        Fuse multimodal detection confidences.
        
        Args:
            spatial_conf: Spatial detection confidence
            temporal_conf: Temporal detection confidence (optional)
            audio_conf: Audio detection confidence (optional)
            temporal_features: Temporal features for advanced fusion
            audio_features: Audio features for advanced fusion
        
        Returns:
            MultimodalConfidence with fused score
        """
        # Video fusion (spatial + temporal)
        if temporal_conf is not None:
            # 70% spatial, 30% temporal (as configured in detection pipeline)
            video_conf = 0.7 * spatial_conf + 0.3 * temporal_conf
        else:
            video_conf = spatial_conf
        
        # Full multimodal fusion
        if audio_conf is not None:
            # Use attention-weighted fusion
            final_conf = self._attention_weighted_fusion(
                spatial_conf=spatial_conf,
                temporal_conf=temporal_conf,
                audio_conf=audio_conf
            )
        else:
            # Video-only
            final_conf = video_conf
        
        # Calculate uncertainty
        uncertainty = self._calculate_uncertainty(
            spatial_conf,
            temporal_conf,
            audio_conf
        )
        
        # Check audio-visual synchronization
        av_sync = None
        if temporal_features and audio_features:
            av_sync = self._check_av_sync(temporal_features, audio_features)
        
        return MultimodalConfidence(
            spatial_confidence=spatial_conf,
            temporal_confidence=temporal_conf,
            audio_confidence=audio_conf,
            video_confidence=video_conf,
            final_confidence=final_conf,
            av_sync_score=av_sync,
            uncertainty=uncertainty,
            fusion_method="attention_weighted" if audio_conf else "video_only"
        )
    
    def _attention_weighted_fusion(
        self,
        spatial_conf: float,
        temporal_conf: Optional[float],
        audio_conf: float
    ) -> float:
        """
        Attention-weighted fusion based on modality reliability.
        
        Higher confidence modalities get more weight.
        """
        # Collect available confidences and base weights
        confidences = []
        base_weights = []
        
        confidences.append(spatial_conf)
        base_weights.append(self.spatial_weight)
        
        if temporal_conf is not None:
            confidences.append(temporal_conf)
            base_weights.append(self.temporal_weight)
        
        confidences.append(audio_conf)
        base_weights.append(self.audio_weight)
        
        # Calculate attention weights (higher confidence = higher weight)
        # Use softmax-like normalization
        attention_scores = np.array(confidences) ** 2  # Square to amplify differences
        attention_weights = attention_scores / np.sum(attention_scores)
        
        # Combine base weights with attention weights
        final_weights = 0.7 * np.array(base_weights) + 0.3 * attention_weights
        final_weights = final_weights / np.sum(final_weights)
        
        # Weighted sum
        fused_confidence = float(np.sum(np.array(confidences) * final_weights))
        
        logger.debug(
            f"Attention fusion: spatial={spatial_conf:.3f} (w={final_weights[0]:.2f}), "
            f"temporal={temporal_conf:.3f if temporal_conf else 0:.3f} "
            f"(w={final_weights[1]:.2f if temporal_conf else 0:.2f}), "
            f"audio={audio_conf:.3f} (w={final_weights[-1]:.2f}) → {fused_confidence:.3f}"
        )
        
        return fused_confidence
    
    def _calculate_uncertainty(
        self,
        spatial_conf: float,
        temporal_conf: Optional[float],
        audio_conf: Optional[float]
    ) -> float:
        """
        Calculate fusion uncertainty.
        
        High uncertainty when:
        - Modalities disagree
        - Low individual confidences
        - Missing modalities
        
        Returns:
            Uncertainty score [0, 1] (higher = more uncertain)
        """
        confidences = [spatial_conf]
        if temporal_conf is not None:
            confidences.append(temporal_conf)
        if audio_conf is not None:
            confidences.append(audio_conf)
        
        # Variance among modalities (disagreement)
        disagreement = float(np.var(confidences))
        
        # Average confidence (low average = high uncertainty)
        avg_conf = float(np.mean(confidences))
        low_confidence_penalty = 1.0 - avg_conf
        
        # Missing modality penalty
        missing_penalty = (3 - len(confidences)) * 0.1
        
        # Combine
        uncertainty = min(1.0, disagreement + 0.3 * low_confidence_penalty + missing_penalty)
        
        return float(uncertainty)
    
    def _check_av_sync(
        self,
        temporal_features: TemporalFeatures,
        audio_features: Dict
    ) -> float:
        """
        Check audio-visual synchronization.
        
        Deepfakes often have misaligned audio and video due to:
        - Separate generation of audio/video
        - Post-processing artifacts
        - Lip-sync issues
        
        Returns:
            Sync score [0, 1] (higher = better sync)
        """
        # Simplified sync check based on energy correlation
        # In real implementation, would check:
        # - Mouth movement vs speech activity
        # - Blink timing vs audio pauses
        # - Head movement vs prosody
        
        # For now, use heuristic:
        # Check if temporal anomaly and audio anomaly are correlated
        temporal_anomaly = temporal_features.temporal_anomaly_score
        audio_anomaly = audio_features.get('anomalies', {}).get('overall', 0.0)
        
        # High correlation = likely synchronized (both fake or both real)
        correlation = 1.0 - abs(temporal_anomaly - audio_anomaly)
        
        return float(correlation)
    
    def check_phoneme_viseme_alignment(
        self,
        mouth_landmarks: np.ndarray,
        audio_segment: np.ndarray
    ) -> float:
        """
        Check phoneme-viseme alignment.
        
        Phoneme: Speech sound
        Viseme: Visual mouth shape
        
        They should match in natural speech.
        
        Args:
            mouth_landmarks: Mouth landmark positions
            audio_segment: Audio waveform
        
        Returns:
            Alignment score [0, 1] (higher = better alignment)
        """
        # TODO: Implement detailed phoneme-viseme matching
        # This requires:
        # 1. Phoneme segmentation from audio
        # 2. Viseme classification from mouth landmarks
        # 3. Temporal alignment
        
        # Placeholder: Return None to indicate not implemented/skipped
        return None
    
    def analyze_emotional_coherence(
        self,
        facial_expression: str,
        voice_emotion: str
    ) -> Optional[float]:
        """
        Analyze emotional coherence between face and voice.
        
        Deepfakes may have mismatched emotions:
        - Happy face with sad voice
        - Neutral face with angry voice
        
        Args:
            facial_expression: Expression label (happy, sad, angry, neutral, etc.)
            voice_emotion: Voice emotion label
        
        Returns:
            Coherence score [0, 1] (higher = more coherent) or None if skipped
        """
        # TODO: Implement emotion-based coherence
        # Would require:
        # 1. Facial expression classification
        # 2. Voice emotion recognition
        # 3. Cross-modal emotion consistency check
        
        # Placeholder: Return None to indicate not implemented/skipped
        return None


# Global multimodal fusion instance
_multimodal_fusion: Optional[MultimodalFusion] = None


def get_multimodal_fusion() -> MultimodalFusion:
    """Get global multimodal fusion instance"""
    global _multimodal_fusion
    if _multimodal_fusion is None:
        _multimodal_fusion = MultimodalFusion()
    return _multimodal_fusion
