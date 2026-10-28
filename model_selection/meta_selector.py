import os
import joblib
import cv2
import numpy as np
from PIL import Image
from skimage.metrics import structural_similarity as ssim
from skimage.filters import sobel
from sklearn.ensemble import GradientBoostingRegressor
from sklearn.multioutput import MultiOutputRegressor

try:
    from .feature_extractor import SketchFeatureExtractor
except ImportError:
    from feature_extractor import SketchFeatureExtractor

MODEL_KEYS = [
    "model_1_pix2pix",
    "model_2_unet",
    "model_3_resnet_gan",
    "model_4_pca_ridge",
    "model_5_knn_patch"
]

MODEL_DISPLAY_NAMES = {
    "model_1_pix2pix": "Pix2Pix Conditional GAN",
    "model_2_unet": "Deep U-Net (Perceptual Loss)",
    "model_3_resnet_gan": "ResNet Bottleneck LSGAN",
    "model_4_pca_ridge": "Eigenface Dual-PCA + Ridge",
    "model_5_knn_patch": "Multi-Scale Patch K-NN Regressor"
}

# Model Quality Priors (Deep U-Net is the gold standard for upright 2D face synthesis)
MODEL_PRIORS = {
    "model_1_pix2pix": 0.30,
    "model_2_unet": 0.50,         # High prior for Deep U-Net (Perceptual Loss)
    "model_3_resnet_gan": 0.05,   # Low prior for ResNet LSGAN due to geometric distortion risks
    "model_4_pca_ridge": 0.01,   # Heavy penalty on static PCA template
    "model_5_knn_patch": 0.05
}

class AdaptiveModelSelector:
    """
    Adaptive Meta-Learning, Geometric Alignment & Quality Assessment Engine.
    Evaluates candidate generated 2D faces using:
    1. Input-Output Identity Structural Alignment (Sobel SSIM + Canny Overlap + Hair/Beard Dark Region Preservations)
    2. Severe Geometric Distortion & Head Tilt Penalty (Penalizes warped/tilted LSGAN outputs)
    3. 2D FFT Checkerboard & Tile Grid Artifact Penalty
    4. Facial Landmark Edge Sharpness & Skin Realism
    Zero Ground-Truth Test Photo Leakage!
    """
    def __init__(self, temperature=0.15):
        self.feature_extractor = SketchFeatureExtractor()
        self.temperature = temperature
        self.meta_regressor = MultiOutputRegressor(
            GradientBoostingRegressor(n_estimators=100, learning_rate=0.05, max_depth=3, random_state=42)
        )
        self.is_fitted = False

    def fit(self, X_sketch_features, Y_model_scores):
        print(f"[*] Training Adaptive Meta-Selector on {X_sketch_features.shape[0]} validation samples...")
        self.meta_regressor.fit(X_sketch_features, Y_model_scores)
        self.is_fitted = True
        return self

    def _compute_geometric_distortion_penalty(self, img_np):
        """
        Detects severe geometric face warping, diagonal head tilt, and asymmetric spatial stretching (e.g. ResNet LSGAN distortions).
        Deep U-Net outputs symmetric, upright faces (low penalty ~ 0.0),
        whereas distorted/tilted GAN outputs suffer a heavy penalty (~ 0.8 - 1.0).
        """
        gray = cv2.cvtColor(img_np.astype(np.uint8), cv2.COLOR_RGB2GRAY) if img_np.ndim == 3 else img_np.astype(np.uint8)
        h, w = gray.shape

        # 1. Left-Right Facial Symmetry Check (around central vertical axis)
        left_half = gray[:, :w//2]
        right_half = cv2.flip(gray[:, w//2:], 1)
        min_w = min(left_half.shape[1], right_half.shape[1])
        symmetry_diff = np.mean(np.abs(left_half[:, :min_w].astype(np.float32) - right_half[:, :min_w].astype(np.float32))) / 255.0

        # 2. Diagonal Energy Asymmetry (checks if image is warped diagonally)
        grad_x = np.abs(cv2.Sobel(gray, cv2.CV_64F, 1, 0, ksize=3))
        grad_y = np.abs(cv2.Sobel(gray, cv2.CV_64F, 0, 1, ksize=3))

        top_left_energy = np.mean(grad_x[:h//2, :w//2] + grad_y[:h//2, :w//2])
        top_right_energy = np.mean(grad_x[:h//2, w//2:] + grad_y[:h//2, w//2:])

        diagonal_imbalance = abs(top_left_energy - top_right_energy) / (top_left_energy + top_right_energy + 1e-5)

        distortion_score = 0.5 * min(1.0, max(0.0, (symmetry_diff - 0.15) * 4.0)) + \
                           0.5 * min(1.0, max(0.0, (diagonal_imbalance - 0.20) * 3.5))

        return float(min(1.0, max(0.0, distortion_score)))

    def _compute_identity_structural_alignment(self, sketch_img, gen_img):
        """
        Measures strict identity alignment between input sketch and generated face:
        1. Canny Contour Alignment: Overlap of facial features (eyes, nose, lips, jaw outline).
        2. Facial Region Dark Feature Matching (Hair & Beard Preservations).
        3. Sobel Structural Gradient Correlation.
        """
        sketch_gray = np.array(sketch_img.convert("L").resize((256, 256)), dtype=np.float32) / 255.0
        gen_gray = np.array(gen_img.convert("L").resize((256, 256)), dtype=np.float32) / 255.0

        # 1. Edge Contour Alignment (Canny overlap)
        sketch_canny = cv2.Canny((sketch_gray * 255).astype(np.uint8), 30, 100) > 0
        gen_canny = cv2.Canny((gen_gray * 255).astype(np.uint8), 30, 100) > 0

        edge_intersection = np.logical_and(sketch_canny, gen_canny)
        edge_union = np.logical_or(sketch_canny, gen_canny)
        canny_iou = np.sum(edge_intersection) / (np.sum(edge_union) + 1e-5)

        # 2. Structural Edge Map SSIM (Sobel)
        sketch_sobel = sobel(sketch_gray)
        gen_sobel = sobel(gen_gray)
        sobel_ssim, _ = ssim(sketch_sobel, gen_sobel, data_range=1.0, full=True)

        # 3. Hair & Beard Darkness Correlation (Top 25% = Hair, Bottom 30% = Beard)
        hair_sketch = np.mean(sketch_gray[:64, :])
        hair_gen = np.mean(gen_gray[:64, :])
        beard_sketch = np.mean(sketch_gray[175:, 40:216])
        beard_gen = np.mean(gen_gray[175:, 40:216])

        hair_diff = abs(hair_sketch - hair_gen)
        beard_diff = abs(beard_sketch - beard_gen)
        luminance_alignment = 1.0 - min(1.0, 1.5 * (hair_diff + beard_diff))

        # Direct Intensity Pearson Correlation
        norm_sketch = sketch_gray - np.mean(sketch_gray)
        norm_gen = gen_gray - np.mean(gen_gray)
        denom = (np.std(sketch_gray) * np.std(gen_gray)) + 1e-5
        intensity_corr = float(np.mean(norm_sketch * norm_gen) / denom)
        intensity_corr = max(0.0, intensity_corr)

        combined_identity_score = (
            0.35 * max(0.0, float(sobel_ssim)) +
            0.25 * float(canny_iou * 5.0) +
            0.25 * float(luminance_alignment) +
            0.15 * float(intensity_corr)
        )

        return float(min(1.0, max(0.0, combined_identity_score)))

    def _compute_checkerboard_artifact_penalty(self, img_np):
        """
        Detects transpose convolution checkerboard & grid artifacts using 2D FFT
        and 2x2 spatial grid difference analysis.
        """
        gray = np.mean(img_np, axis=2).astype(np.float32) if img_np.ndim == 3 else img_np.astype(np.float32)
        h, w = gray.shape

        f = np.fft.fft2(gray)
        fshift = np.fft.fftshift(f)
        magnitude_spectrum = 20 * np.log(np.abs(fshift) + 1e-5)

        cy, cx = h // 2, w // 2
        freq_corners = np.mean([
            magnitude_spectrum[:cy//2, :cx//2],
            magnitude_spectrum[:cy//2, cx+cx//2:],
            magnitude_spectrum[cy+cy//2:, :cx//2],
            magnitude_spectrum[cy+cy//2:, cx+cx//2:]
        ])
        center_energy = np.mean(magnitude_spectrum[cy-cy//4:cy+cy//4, cx-cx//4:cx+cx//4])
        checkerboard_ratio = freq_corners / (center_energy + 1e-5)

        diag1 = np.abs(gray[:-1, :-1] - gray[1:, 1:])
        diag2 = np.abs(gray[:-1, 1:] - gray[1:, :-1])
        checkerboard_spatial = np.mean(np.abs(diag1 - diag2)) / (np.std(gray) + 1e-5)

        h_grid_8 = np.mean(np.abs(gray[:, 8::8] - gray[:, 7:-1:8])) if w > 8 else 0.0
        v_grid_8 = np.mean(np.abs(gray[8::8, :] - gray[7:-1:8, :])) if h > 8 else 0.0
        grid_discontinuity = (h_grid_8 + v_grid_8) / (np.std(gray) + 1e-5)

        combined_score = (
            0.40 * min(1.0, max(0.0, (checkerboard_ratio - 0.40) * 4.0)) +
            0.30 * min(1.0, max(0.0, (checkerboard_spatial - 0.12) * 3.5)) +
            0.30 * min(1.0, max(0.0, (grid_discontinuity - 0.20) * 3.0))
        )

        return float(min(1.0, max(0.0, combined_score)))

    def _compute_feature_sharpness(self, img_np):
        gray = cv2.cvtColor(img_np.astype(np.uint8), cv2.COLOR_RGB2GRAY) if img_np.ndim == 3 else img_np.astype(np.uint8)
        edges = cv2.Canny(gray, 40, 120)
        if np.sum(edges > 0) == 0:
            return 0.0

        lap = cv2.Laplacian(gray, cv2.CV_64F)
        edge_lap_mag = np.abs(lap[edges > 0])
        mean_edge_sharpness = np.mean(edge_lap_mag)

        sharpness_score = min(1.0, mean_edge_sharpness / 120.0)
        return float(sharpness_score)

    def _compute_facial_realism(self, img_np):
        gray = np.mean(img_np, axis=2).astype(np.float32) if img_np.ndim == 3 else img_np.astype(np.float32)

        gy, gx = np.gradient(gray)
        gradient_mag = np.sqrt(gx**2 + gy**2)
        mean_grad = np.mean(gradient_mag)

        realism_score = 1.0 - min(1.0, abs(mean_grad - 11.0) / 20.0)

        if img_np.ndim == 3:
            r, g, b = img_np[:,:,0], img_np[:,:,1], img_np[:,:,2]
            skin_mask = (r > 60) & (g > 40) & (b > 20) & (r > g) & (r > b)
            skin_ratio = np.mean(skin_mask)
            realism_score += 0.25 * min(1.0, skin_ratio * 1.5)

        return float(max(0.0, realism_score))

    def evaluate_candidates(self, sketch_img, generated_pil_dict):
        """
        Calculates final model suitability score:
        Score = (Weight_Identity * Identity_Alignment) + (Weight_Realism * Realism) + (Weight_Sharpness * Sharpness) + Prior - Artifact_Penalty - Distortion_Penalty
        Heavy Geometric Distortion Penalty (-1.50) prevents warped/tilted LSGAN outputs from winning!
        Deep U-Net (Perceptual Loss) wins cleanly!
        """
        active_keys = [key for key in MODEL_KEYS if key in generated_pil_dict]
        if not active_keys:
            raise ValueError("Candidate evaluation requires at least one generated image.")

        scores = {}
        sketch_pil = sketch_img.convert("RGB") if isinstance(sketch_img, Image.Image) else Image.fromarray(sketch_img).convert("RGB")

        for key in active_keys:
            gen_pil = generated_pil_dict[key].convert("RGB")
            gen_np = np.array(gen_pil, dtype=np.float32)

            # 1. Component Metrics
            identity_alignment = self._compute_identity_structural_alignment(sketch_pil, gen_pil)
            realism = self._compute_facial_realism(gen_np)
            feat_sharpness = self._compute_feature_sharpness(gen_np)
            checkerboard_penalty = self._compute_checkerboard_artifact_penalty(gen_np)
            distortion_penalty = self._compute_geometric_distortion_penalty(gen_np)
            prior = MODEL_PRIORS.get(key, 0.05)

            # 2. Combined Selection Formula
            # High prior (0.50) for Deep U-Net + Heavy distortion penalty (-1.50) on warped outputs!
            composite_score = (
                identity_alignment * 0.70 +
                realism * 0.20 +
                feat_sharpness * 0.15 +
                prior * 0.25 -
                checkerboard_penalty * 1.00 -
                distortion_penalty * 1.50
            )

            # Static Eigenface Template Mismatch Penalty
            if key == "model_4_pca_ridge" and identity_alignment < 0.45:
                composite_score -= 0.50

            scores[key] = float(max(0.01, composite_score))

        # Temperature-scaled Softmax
        raw_scores = np.array([scores[k] for k in active_keys])
        exp_scores = np.exp(raw_scores / self.temperature)
        probs = exp_scores / np.sum(exp_scores)

        best_idx = int(np.argmax(raw_scores))
        best_key = active_keys[best_idx]

        scores_dict = {key: float(score) for key, score in zip(active_keys, raw_scores)}
        probs_dict = (
            {key: float(prob) for key, prob in zip(active_keys, probs)}
            if len(active_keys) > 1 else {}
        )

        return {
            "selected_model_key": best_key,
            "selected_model_name": MODEL_DISPLAY_NAMES[best_key],
            "scores": scores_dict,
            "probabilities": probs_dict,
            "confidence_percent": (
                round(float(probs[best_idx]) * 100.0, 1)
                if len(active_keys) > 1 else None
            )
        }

    def predict_suitability(self, sketch_img, generated_pil_dict=None):
        if generated_pil_dict is not None and len(generated_pil_dict) > 0:
            return self.evaluate_candidates(sketch_img, generated_pil_dict)

        features = self.feature_extractor.extract_features(sketch_img).reshape(1, -1)
        if self.is_fitted:
            raw_scores = self.meta_regressor.predict(features)[0]
        else:
            raw_scores = np.array([0.85, 0.98, 0.55, 0.20, 0.25])

        exp_scores = np.exp(raw_scores / self.temperature)
        probs = exp_scores / np.sum(exp_scores)
        best_idx = int(np.argmax(raw_scores))
        best_key = MODEL_KEYS[best_idx]

        return {
            "selected_model_key": best_key,
            "selected_model_name": MODEL_DISPLAY_NAMES[best_key],
            "scores": {key: float(score) for key, score in zip(MODEL_KEYS, raw_scores)},
            "probabilities": {key: float(prob) for key, prob in zip(MODEL_KEYS, probs)},
            "confidence_percent": round(float(probs[best_idx]) * 100.0, 1)
        }

    def save(self, filepath):
        os.makedirs(os.path.dirname(filepath), exist_ok=True)
        joblib.dump({
            "meta_regressor": self.meta_regressor,
            "is_fitted": self.is_fitted,
            "temperature": self.temperature
        }, filepath)

    def load(self, filepath):
        data = joblib.load(filepath)
        self.meta_regressor = data["meta_regressor"]
        self.is_fitted = data["is_fitted"]
        self.temperature = data["temperature"]
