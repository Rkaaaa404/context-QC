# %% [markdown]
# # NUSAQC — MODEL 1 FULL PIPELINE (FRESHNESS ENGINE)
# ## Preprocessing, EDA, Dual-Split Evaluation, FFE Secondary Test, ONNX INT8 & Edge Latency Benchmark
#
# **Proyek:** NusaQC — COMPFEST 18 AIC (Smart Manufacturing Track)
# **Arsitektur:** MobileNetV3-Small (Feature Extractor + SNI 2729:2013 Freshness Classifier)
#
# **Struktur Pipeline Komprehensif:**
# 1. **Setup & Autodiscovery:** Deteksi environment Kaggle GPU/CPU & autodiscovery path dataset DaFiF dan FFE.
# 2. **Parsing & Organoleptic Mapping:** Pemetaan hari penyimpanan ke Grade A, B, C berdasarkan standar SNI 2729:2013.
# 3. **Exploratory Data Analysis (EDA):** Visualisasi distribusi kelas, spesies, degradasi hari, perbandingan DaFiF vs FFE, dan grid sampel citra (Auto-saved).
# 4. **Anti-Leakage Data Augmentation & Class Balancing:** Class-weighted loss & regulasi spasial (RandomErasing/Cutout, ColorJitter) untuk menekan background bias laboratorium.
# 5. **Dual-Split Evaluation:**
#    - **Random Split (70/15/15):** Benchmark baseline (indikator spatiotemporal leakage).
#    - **Grouped Split (by Day & Session):** Evaluasi jujur performa generalisasi waktu/sesi baru.
# 6. **Training Engine with Epoch Tracking:** Training dengan Cosine Annealing, AMP Mixed Precision, dan tracking metrik lengkap (Loss, Acc, Macro F1).
# 7. **Secondary Validation on FFE:** Pengujian Out-of-Distribution & Cross-Modality (Macro Eye close-up).
# 8. **Visualisasi Hasil Evaluasi:** Plot kurva training, confusion matrix komparatif, dan grid analisis prediksi benar vs salah (Auto-saved).
# 9. **ONNX Export (Opset 17) & INT8 Quantization:** Ekspor model stabil tanpa error Dynamo/ShapeInference.
# 10. **CPU Inference Latency Benchmark:** Pengukuran latensi inferensi (ms/frame) PyTorch vs ONNX FP32 vs ONNX INT8 untuk simulasi edge device (Raspberry Pi 5).

# %%
# Install dependencies jika dijalankan di environment baru
import sys
import subprocess

required_pkgs = ["onnx", "onnxruntime", "onnxscript", "seaborn", "matplotlib"]
missing_pkgs = []
for pkg in required_pkgs:
    try:
        __import__(pkg)
    except ImportError:
        missing_pkgs.append(pkg)

if missing_pkgs:
    print(f"Installing missing packages: {missing_pkgs}...")
    subprocess.check_call([sys.executable, "-m", "pip", "install", "-q"] + missing_pkgs)

# %%
import os
import re
import time
import shutil
import random
import urllib.request
from pathlib import Path
from typing import List, Tuple, Dict, Optional

import numpy as np
import pandas as pd
import matplotlib.pyplot as plt
import seaborn as sns
from PIL import Image

import torch
import torch.nn as nn
import torch.optim as optim
from torch.utils.data import DataLoader, Dataset
from torchvision import transforms, models

from sklearn.model_selection import train_test_split, GroupShuffleSplit
from sklearn.metrics import classification_report, confusion_matrix, f1_score, precision_recall_fscore_support
from sklearn.utils.class_weight import compute_class_weight

import onnx
import onnxruntime as ort
from onnxruntime.quantization import quantize_dynamic, QuantType

# Konfigurasi Tampilan Visualisasi
plt.style.use('seaborn-v0_8-whitegrid' if 'seaborn-v0_8-whitegrid' in plt.style.available else 'default')
plt.rcParams['font.sans-serif'] = 'DejaVu Sans'
plt.rcParams['figure.autolayout'] = True

# Fix HTTP 403 Forbidden ketika download pretrained weights di Kaggle
opener = urllib.request.build_opener()
opener.addheaders = [('User-Agent', 'Mozilla/5.0 (Windows NT 10.0; Win64; x64)')]
urllib.request.install_opener(opener)

# Matikan progress bar download PyTorch untuk mencegah deadlock di Kaggle
torch.hub.set_dir("/kaggle/working/.cache_torch")

# Set Random Seed untuk Reproducibility
SEED = 42
def seed_everything(seed=42):
    random.seed(seed)
    os.environ['PYTHONHASHSEED'] = str(seed)
    np.random.seed(seed)
    torch.manual_seed(seed)
    if torch.cuda.is_available():
        torch.cuda.manual_seed(seed)
        torch.cuda.manual_seed_all(seed)
        torch.backends.cudnn.deterministic = True
seed_everything(SEED)

# System Device Check
if torch.cuda.is_available():
    DEVICE = torch.device("cuda:0")
    print(f"[GPU ACTIVE] Using GPU: {torch.cuda.get_device_name(0)} (Count: {torch.cuda.device_count()})")
else:
    DEVICE = torch.device("cpu")
    print("[DEVICE] Running on CPU.")

# %% [markdown]
# # 1. Directory Setup & Autodiscovery
# Mencari folder dataset DaFiF dan FFE secara otomatis di berbagai path Kaggle atau lokal.

# %%
def autodiscover_dataset_paths():
    """Mencari path dataset DaFiF dan FFE di Kaggle input atau direktori lokal."""
    dafif_candidates = [
        Path("/kaggle/input/datasets/raykapranandita/dataset-for-fishs-freshness-problems"),
        Path("/kaggle/input/dataset-for-fishs-freshness-problems"),
        Path("/kaggle/input/dafif-fish-freshness"),
        Path("models/datasets/model-1/dafif"),
        Path("datasets/model-1/dafif"),
        Path("./dafif")
    ]
    ffe_candidates = [
        Path("/kaggle/input/datasets/raykapranandita/the-freshness-of-the-fish-eyes-dataset-ffe"),
        Path("/kaggle/input/the-freshness-of-the-fish-eyes-dataset-ffe"),
        Path("/kaggle/input/ffe-fish-eyes"),
        Path("models/datasets/model-1/ffe"),
        Path("datasets/model-1/ffe"),
        Path("./ffe")
    ]
    
    dafif_dir = None
    for cand in dafif_candidates:
        if cand.exists():
            dafif_dir = cand
            break
            
    ffe_dir = None
    for cand in ffe_candidates:
        if cand.exists():
            ffe_dir = cand
            break
            
    # Fallback search jika path terstruktur berbeda di Kaggle
    if dafif_dir is None and Path("/kaggle/input").exists():
        for p in Path("/kaggle/input").rglob("*"):
            if p.is_dir() and "freshness" in p.name.lower() and "eye" not in p.name.lower():
                dafif_dir = p
                break
                
    if ffe_dir is None and Path("/kaggle/input").exists():
        for p in Path("/kaggle/input").rglob("*"):
            if p.is_dir() and ("eye" in p.name.lower() or "ffe" in p.name.lower()):
                ffe_dir = p
                break

    return dafif_dir, ffe_dir

DAFIF_DIR, FFE_DIR = autodiscover_dataset_paths()

WORKING_DIR = Path("/kaggle/working") if Path("/kaggle/working").exists() else Path(".")
OUTPUT_DIR = WORKING_DIR / "output_model1"
OUTPUT_DIR.mkdir(parents=True, exist_ok=True)

# Hyperparameter Training
BATCH_SIZE = 64
EPOCHS = 12
LEARNING_RATE = 1e-3
WEIGHT_DECAY = 1e-2
TARGET_SIZE = (224, 224)
IMAGE_EXTENSIONS = {".jpg", ".jpeg", ".png", ".bmp", ".webp"}
NUM_WORKERS = 0

print(f"🎯 DaFiF Directory : {DAFIF_DIR} (Found: {DAFIF_DIR is not None})")
print(f"🎯 FFE Directory   : {FFE_DIR} (Found: {FFE_DIR is not None})")
print(f"📂 Output Directory: {OUTPUT_DIR.resolve()}")

# %% [markdown]
# # 2. Dataset Parsing & SNI 2729:2013 Grade Mapping
# Memetakan hari penyimpanan es pada DaFiF ke standar mutu organoleptik SNI:
# - **Day 1–2** : `Grade_A` (Prima / Sangat Segar)
# - **Day 3–6** : `Grade_B` (Segar / Konsumsi Pasar Lokal)
# - **Day 7–11**: `Grade_C` (Busuk / Tidak Layak Konsumsi — Reject)

# %%
def get_dafif_grade(day_num: int) -> str:
    """Pemetaan SNI 2729:2013 Organoleptik berdasarkan hari penyimpanan es."""
    if day_num in [1, 2]:
        return "Grade_A"
    elif day_num in [3, 4, 5, 6]:
        return "Grade_B"
    elif day_num >= 7:
        return "Grade_C"
    return None

def get_ffe_grade(folder_name: str) -> Optional[str]:
    """Pemetaan folder dataset FFE ke format Grade NusaQC."""
    fn = folder_name.strip().lower()
    # PENTING: Evaluasi 'not fresh' terlebih dahulu sebelum 'fresh' agar tidak tertangkap substring
    if "not fresh" in fn or fn.endswith("- not fresh"):
        return "Grade_C"
    elif "highly fresh" in fn or fn.endswith("- highly fresh"):
        return "Grade_A"
    elif "fresh" in fn or fn.endswith("- fresh"):
        return "Grade_B"
    return None

# 1. Parsing DaFiF
dafif_records = []
if DAFIF_DIR and DAFIF_DIR.exists():
    for img_path in DAFIF_DIR.rglob("*"):
        if img_path.is_file() and img_path.suffix.lower() in IMAGE_EXTENSIONS:
            path_str = str(img_path)
            day_match = re.search(r"Day\s*(\d+)", path_str, re.IGNORECASE)
            if day_match:
                day_num = int(day_match.group(1))
                grade = get_dafif_grade(day_num)
                if grade:
                    sess_match = re.search(r"(Session\s*\d+)", path_str, re.IGNORECASE)
                    sess_str = sess_match.group(1).replace(" ", "_") if sess_match else "Session_1"
                    
                    sp_match = re.search(r"(Mackerel|Tilapia|Tuna)", path_str, re.IGNORECASE)
                    sp_str = sp_match.group(1).capitalize() if sp_match else "Unknown"
                    
                    group_id = f"Day_{day_num}_{sess_str}_{sp_str}"
                    dafif_records.append({
                        "filepath": str(img_path),
                        "filename": img_path.name,
                        "grade": grade,
                        "day": day_num,
                        "session": sess_str,
                        "species": sp_str,
                        "group_id": group_id,
                        "dataset": "DaFiF_Primary"
                    })

df_dafif = pd.DataFrame(dafif_records)
print(f"\n[DAFIF DATASET PARSED] Total Sampel: {len(df_dafif)}")
if len(df_dafif) == 0:
    raise ValueError(f"Dataset DaFiF tidak ditemukan di {DAFIF_DIR}. Pastikan dataset DaFiF telah di-attach ke notebook.")

print(df_dafif["grade"].value_counts())

# 2. Parsing FFE (Secondary Validation Set)
ffe_records = []
if FFE_DIR and FFE_DIR.exists():
    for folder in FFE_DIR.iterdir():
        if folder.is_dir():
            grade = get_ffe_grade(folder.name)
            if grade:
                for img_path in folder.rglob("*"):
                    if img_path.is_file() and img_path.suffix.lower() in IMAGE_EXTENSIONS:
                        ffe_records.append({
                            "filepath": str(img_path),
                            "filename": img_path.name,
                            "grade": grade,
                            "dataset": "FFE_Secondary"
                        })

df_ffe = pd.DataFrame(ffe_records)
print(f"\n[FFE DATASET PARSED] Total Sampel: {len(df_ffe)}")
if len(df_ffe) > 0:
    print(df_ffe["grade"].value_counts())

# %% [markdown]
# # 3. Exploratory Data Analysis (EDA) & Visualisasi
# Modul visualisasi data komprehensif untuk menganalisis distribusi kelas, ketimpangan data (imbalance), dan karakteristik visual sampel.

# %%
GRADE_ORDER = ["Grade_A", "Grade_B", "Grade_C"]
GRADE_COLORS = {"Grade_A": "#2ECC71", "Grade_B": "#F39C12", "Grade_C": "#E74C3C"}
PALETTE = [GRADE_COLORS[g] for g in GRADE_ORDER]

def run_comprehensive_eda(df_dafif: pd.DataFrame, df_ffe: pd.DataFrame, out_dir: Path):
    """Membuat dan menyimpan chart EDA statistik dataset."""
    fig, axes = plt.subplots(2, 2, figsize=(16, 12))
    fig.suptitle("NusaQC Model 1: Exploratory Data Analysis (DaFiF & FFE Datasets)", fontsize=16, fontweight="bold", y=0.98)

    # Subplot 1: Distribusi Kelas DaFiF
    ax1 = axes[0, 0]
    dafif_counts = df_dafif["grade"].value_counts().reindex(GRADE_ORDER)
    bars1 = ax1.bar(GRADE_ORDER, dafif_counts.values, color=PALETTE, edgecolor="black", linewidth=1.2)
    ax1.set_title("1. Distribusi Kelas DaFiF (Primary Training Set)", fontsize=12, fontweight="bold")
    ax1.set_ylabel("Jumlah Sampel Citra")
    for bar in bars1:
        yval = bar.get_height()
        pct = (yval / len(df_dafif)) * 100
        ax1.text(bar.get_x() + bar.get_width()/2.0, yval + 15, f"{int(yval)}\n({pct:.1f}%)", ha="center", va="bottom", fontsize=10, fontweight="bold")
    ax1.set_ylim(0, max(dafif_counts.values) * 1.18)

    # Subplot 2: Distribusi Kelas per Spesies Ikan (DaFiF)
    ax2 = axes[0, 1]
    sp_df = df_dafif.groupby(["species", "grade"]).size().unstack(fill_value=0).reindex(columns=GRADE_ORDER)
    sp_df.plot(kind="bar", stacked=False, ax=ax2, color=PALETTE, edgecolor="black", linewidth=1.0)
    ax2.set_title("2. Distribusi Kelas Mutu per Spesies Ikan (DaFiF)", fontsize=12, fontweight="bold")
    ax2.set_xlabel("Spesies Ikan")
    ax2.set_ylabel("Jumlah Citra")
    ax2.tick_params(axis="x", rotation=0)
    ax2.legend(title="Mutu SNI")

    # Subplot 3: Degradasi Mutu Berdasarkan Hari Penyimpanan Es (Day 1 - 11)
    ax3 = axes[1, 0]
    day_grade_df = df_dafif.groupby(["day", "grade"]).size().unstack(fill_value=0).reindex(columns=GRADE_ORDER)
    day_grade_df.plot(kind="bar", stacked=True, ax=ax3, color=PALETTE, edgecolor="black", linewidth=0.8)
    ax3.set_title("3. Degradasi Mutu SNI Berdasarkan Hari Penyimpanan Es (Day 1-11)", fontsize=12, fontweight="bold")
    ax3.set_xlabel("Hari Penyimpanan Es (Storage Days)")
    ax3.set_ylabel("Total Citra per Hari")
    ax3.tick_params(axis="x", rotation=0)
    ax3.legend(title="Mutu SNI")

    # Subplot 4: Perbandingan Distribusi DaFiF vs FFE
    ax4 = axes[1, 1]
    if len(df_ffe) > 0:
        ffe_counts = df_ffe["grade"].value_counts().reindex(GRADE_ORDER).fillna(0)
        comp_df = pd.DataFrame({
            "DaFiF (Whole-Body)": dafif_counts,
            "FFE (Eye Close-Up)": ffe_counts
        })
        comp_df.plot(kind="bar", ax=ax4, color=["#3498DB", "#9B59B6"], edgecolor="black", linewidth=1.0)
        ax4.set_title("4. Perbandingan Distribusi DaFiF vs FFE (Secondary)", fontsize=12, fontweight="bold")
        ax4.set_ylabel("Jumlah Sampel")
        ax4.tick_params(axis="x", rotation=0)
        ax4.legend(title="Dataset")
    else:
        ax4.text(0.5, 0.5, "Dataset FFE Tidak Tersedia", ha="center", va="center", fontsize=12)

    plt.tight_layout(rect=[0, 0.03, 1, 0.95])
    eda_plot_path = out_dir / "eda_dataset_distribution.png"
    plt.savefig(eda_plot_path, dpi=300)
    plt.show()
    print(f"📊 Chart EDA tersimpan: {eda_plot_path}")

def visualize_sample_images_grid(df: pd.DataFrame, out_dir: Path, n_per_grade: int = 3):
    """Menampilkan grid citra asli dari tiap kelas mutu beserta label metadata."""
    fig, axes = plt.subplots(3, n_per_grade, figsize=(4 * n_per_grade, 10))
    fig.suptitle("Sampel Visual Citra DaFiF per Kelas Mutu SNI 2729:2013", fontsize=15, fontweight="bold")

    for row_idx, grade in enumerate(GRADE_ORDER):
        samples = df[df["grade"] == grade].sample(min(n_per_grade, len(df[df["grade"] == grade])), random_state=SEED)
        for col_idx, (_, row) in enumerate(samples.iterrows()):
            ax = axes[row_idx, col_idx]
            try:
                img = Image.open(row["filepath"]).convert("RGB")
                ax.imshow(img)
                ax.set_title(f"{grade}\nDay {row['day']} | {row['species']} ({row['session']})", fontsize=9, fontweight="bold", color=GRADE_COLORS[grade])
            except Exception as e:
                ax.text(0.5, 0.5, f"Error: {e}", ha="center")
            ax.axis("off")

    plt.tight_layout()
    samples_path = out_dir / "eda_sample_images_by_grade.png"
    plt.savefig(samples_path, dpi=300)
    plt.show()
    print(f"🖼️ Grid sampel visual tersimpan: {samples_path}")

run_comprehensive_eda(df_dafif, df_ffe, OUTPUT_DIR)
visualize_sample_images_grid(df_dafif, OUTPUT_DIR, n_per_grade=4)

# %% [markdown]
# # 4. Anti-Leakage Data Augmentations & Ultra-Fast RAM Dataset
# - Menambahkan **RandomErasing (Cutout)** dan **ColorJitter** untuk memaksa model belajar fitur morfologi ikan (mata, insang, lendir) alih-alih menghafal latar belakang laboratorium.
# - Menggunakan **FastRAMFishDataset** untuk mengeliminasi bottleneck disk I/O di Kaggle.

# %%
GRADE_MAP = {"Grade_A": 0, "Grade_B": 1, "Grade_C": 2}
REVERSE_GRADE_MAP = {0: "Grade_A", 1: "Grade_B", 2: "Grade_C"}

IMAGENET_MEAN = [0.485, 0.456, 0.406]
IMAGENET_STD = [0.229, 0.224, 0.225]

# Augmentasi yang diperkuat untuk mencegah overfit pada latar belakang meja DaFiF
train_transform = transforms.Compose([
    transforms.RandomResizedCrop(TARGET_SIZE, scale=(0.85, 1.0)),
    transforms.RandomHorizontalFlip(p=0.5),
    transforms.RandomRotation(degrees=15),
    transforms.ColorJitter(brightness=0.2, contrast=0.2, saturation=0.2, hue=0.05),
    transforms.ToTensor(),
    transforms.Normalize(IMAGENET_MEAN, IMAGENET_STD),
    transforms.RandomErasing(p=0.25, scale=(0.02, 0.2), ratio=(0.3, 3.3), value="random")
])

eval_transform = transforms.Compose([
    transforms.Resize(TARGET_SIZE),
    transforms.ToTensor(),
    transforms.Normalize(IMAGENET_MEAN, IMAGENET_STD)
])

class FastRAMFishDataset(Dataset):
    """
    Menyimpan seluruh citra dalam RAM dalam format RGB ter-resize.
    Mempercepat perulangan epoch hingga 100x lipat dan menghemat waktu GPU Kaggle.
    """
    def __init__(self, df: pd.DataFrame, transform=None, desc="Preloading"):
        self.transform = transform
        self.items = []
        self.filepaths = []
        self.labels = []
        
        print(f"Pre-loading {len(df)} images into RAM ({desc})...")
        for _, row in df.iterrows():
            img_path = row["filepath"]
            label = GRADE_MAP[row["grade"]]
            try:
                with Image.open(img_path) as img:
                    img_rgb = img.convert("RGB").resize(TARGET_SIZE, Image.Resampling.BILINEAR)
                    self.items.append(img_rgb)
                    self.labels.append(label)
                    self.filepaths.append(img_path)
            except Exception:
                continue
        print(f"  └─ Selesai! {len(self.items)} citra tersimpan di RAM.")

    def __len__(self):
        return len(self.items)

    def __getitem__(self, idx):
        img_pil = self.items[idx]
        label = self.labels[idx]
        if self.transform:
            img_tensor = self.transform(img_pil)
        else:
            img_tensor = transforms.ToTensor()(img_pil)
        return img_tensor, label

# %% [markdown]
# # 5. Dual-Split Strategy (Random Split vs Grouped Split)
# Membandingkan dua strategi pembagian data untuk mengevaluasi data leakage:
# 1. **Random Split (70/15/15 Stratified):** Evaluasi konvensional.
# 2. **Grouped Split (by Day & Session):** Memastikan sesi/hari pada test set terisolasi total dari train set.

# %%
# A. RANDOM SPLIT (70/15/15)
train_df_rand, test_val_df_rand = train_test_split(df_dafif, test_size=0.30, random_state=SEED, stratify=df_dafif["grade"])
val_df_rand, test_df_rand = train_test_split(test_val_df_rand, test_size=0.50, random_state=SEED, stratify=test_val_df_rand["grade"])

print("========================================================")
print(f"1. RANDOM SPLIT -> Train: {len(train_df_rand)}, Val: {len(val_df_rand)}, Test: {len(test_df_rand)}")
print(f"   Train Grade Distribution:\n{train_df_rand['grade'].value_counts().to_dict()}")
print("========================================================")

# B. GROUPED SPLIT (by Day + Session)
gss = GroupShuffleSplit(n_splits=1, test_size=0.30, random_state=SEED)
train_idx, test_val_idx = next(gss.split(df_dafif, groups=df_dafif["group_id"]))

train_df_group = df_dafif.iloc[train_idx]
test_val_df_group = df_dafif.iloc[test_val_idx]

gss_val = GroupShuffleSplit(n_splits=1, test_size=0.50, random_state=SEED)
val_sub_idx, test_sub_idx = next(gss_val.split(test_val_df_group, groups=test_val_df_group["group_id"]))

val_df_group = test_val_df_group.iloc[val_sub_idx]
test_df_group = test_val_df_group.iloc[test_sub_idx]

print(f"2. GROUPED SPLIT -> Train: {len(train_df_group)}, Val: {len(val_df_group)}, Test: {len(test_df_group)}")
print(f"   Train Grade Distribution:\n{train_df_group['grade'].value_counts().to_dict()}")
print(f"   Test  Grade Distribution:\n{test_df_group['grade'].value_counts().to_dict()}")
print("========================================================")

# %% [markdown]
# # 6. Model Architecture & Training Engine with History Tracking
# Menggunakan **MobileNetV3-Small** dengan **Class-Weighted CrossEntropyLoss** untuk menyeimbangkan penalti terhadap kelas minoritas (Grade A).

# %%
def build_mobilenet_v3_small():
    """Inisialisasi MobileNetV3-Small dengan Pretrained ImageNet Weights."""
    try:
        model = models.mobilenet_v3_small(weights=models.MobileNet_V3_Small_Weights.DEFAULT)
        print("  └─ Pretrained ImageNet Weights berhasil dimuat.")
    except Exception as e:
        print(f"  └─ Direct weights loading failed ({e}). Mencoba via torch.hub...")
        model = models.mobilenet_v3_small(weights=None)
        url = "https://download.pytorch.org/models/mobilenet_v3_small-047dcff4.pth"
        try:
            state_dict = torch.hub.load_state_dict_from_url(url, progress=False, check_hash=True)
            model.load_state_dict(state_dict)
            print("  └─ Pretrained ImageNet weights berhasil dimuat via torch.hub.")
        except Exception as e2:
            print(f"  └─ Warning: Fallback inisialisasi bobot acak ({e2}).")

    in_features = model.classifier[3].in_features
    model.classifier[3] = nn.Linear(in_features, 3)
    return model

def calculate_class_weights(df: pd.DataFrame) -> torch.Tensor:
    """Menghitung bobot kelas berimbang (balanced class weights)."""
    labels = [GRADE_MAP[g] for g in df["grade"]]
    unique_classes = np.array([0, 1, 2])
    weights = compute_class_weight(class_weight="balanced", classes=unique_classes, y=labels)
    weights_tensor = torch.tensor(weights, dtype=torch.float32).to(DEVICE)
    print(f"  └─ Computed Class Weights: Grade_A: {weights[0]:.3f}, Grade_B: {weights[1]:.3f}, Grade_C: {weights[2]:.3f}")
    return weights_tensor

def train_and_evaluate(train_df: pd.DataFrame, val_df: pd.DataFrame, test_df: pd.DataFrame, experiment_name: str = "Exp"):
    """Training engine lengkap dengan tracking epoch history dan evaluasi komprehensif."""
    print(f"\n========================================================")
    print(f" MEMULAI EKSPERIMEN: {experiment_name.upper()}")
    print(f"========================================================")

    # 1. Dataset & Loaders
    ds_train = FastRAMFishDataset(train_df, train_transform, desc=f"{experiment_name} Train")
    ds_val = FastRAMFishDataset(val_df, eval_transform, desc=f"{experiment_name} Val")
    ds_test = FastRAMFishDataset(test_df, eval_transform, desc=f"{experiment_name} Test")

    train_loader = DataLoader(ds_train, batch_size=BATCH_SIZE, shuffle=True, num_workers=NUM_WORKERS)
    val_loader = DataLoader(ds_val, batch_size=BATCH_SIZE, shuffle=False, num_workers=NUM_WORKERS)
    test_loader = DataLoader(ds_test, batch_size=BATCH_SIZE, shuffle=False, num_workers=NUM_WORKERS)

    # 2. Model, Loss, Optimizer & Scheduler
    model = build_mobilenet_v3_small().to(DEVICE)
    class_weights = calculate_class_weights(train_df)
    criterion = nn.CrossEntropyLoss(weight=class_weights)
    
    optimizer = optim.AdamW(model.parameters(), lr=LEARNING_RATE, weight_decay=WEIGHT_DECAY)
    scheduler = optim.lr_scheduler.CosineAnnealingLR(optimizer, T_max=EPOCHS, eta_min=1e-5)

    use_cuda = (DEVICE.type == "cuda")
    scaler = torch.amp.GradScaler("cuda", enabled=use_cuda) if hasattr(torch, "amp") and hasattr(torch.amp, "GradScaler") else torch.cuda.amp.GradScaler(enabled=use_cuda)

    best_val_f1 = 0.0
    best_model_weights = None

    history = {
        "train_loss": [], "val_loss": [],
        "train_acc": [], "val_acc": [],
        "train_f1": [], "val_f1": []
    }

    print(f"\n🚀 Training selama {EPOCHS} epoch...")
    for epoch in range(1, EPOCHS + 1):
        t0 = time.time()
        
        # --- TRAIN PHASE ---
        model.train()
        train_loss, train_corrects = 0.0, 0
        train_preds_all, train_labels_all = [], []
        
        for inputs, labels in train_loader:
            inputs, labels = inputs.to(DEVICE), labels.to(DEVICE)
            optimizer.zero_grad()
            
            if hasattr(torch, "amp") and hasattr(torch.amp, "autocast"):
                with torch.amp.autocast(device_type="cuda", enabled=use_cuda):
                    outputs = model(inputs)
                    loss = criterion(outputs, labels)
            else:
                with torch.cuda.amp.autocast(enabled=use_cuda):
                    outputs = model(inputs)
                    loss = criterion(outputs, labels)

            scaler.scale(loss).backward()
            scaler.step(optimizer)
            scaler.update()
            
            _, preds = torch.max(outputs, 1)
            train_loss += loss.item() * inputs.size(0)
            train_corrects += torch.sum(preds == labels.data).item()
            train_preds_all.extend(preds.cpu().numpy())
            train_labels_all.extend(labels.cpu().numpy())
            
        scheduler.step()
        epoch_train_loss = train_loss / len(ds_train)
        epoch_train_acc = train_corrects / len(ds_train)
        epoch_train_f1 = f1_score(train_labels_all, train_preds_all, average="macro", zero_division=0)

        # --- VAL PHASE ---
        model.eval()
        val_loss, val_corrects = 0.0, 0
        val_preds_all, val_labels_all = [], []
        
        with torch.no_grad():
            for inputs, labels in val_loader:
                inputs, labels = inputs.to(DEVICE), labels.to(DEVICE)
                if hasattr(torch, "amp") and hasattr(torch.amp, "autocast"):
                    with torch.amp.autocast(device_type="cuda", enabled=use_cuda):
                        outputs = model(inputs)
                        loss = criterion(outputs, labels)
                else:
                    with torch.cuda.amp.autocast(enabled=use_cuda):
                        outputs = model(inputs)
                        loss = criterion(outputs, labels)
                        
                _, preds = torch.max(outputs, 1)
                val_loss += loss.item() * inputs.size(0)
                val_corrects += torch.sum(preds == labels.data).item()
                val_preds_all.extend(preds.cpu().numpy())
                val_labels_all.extend(labels.cpu().numpy())

        epoch_val_loss = val_loss / len(ds_val)
        epoch_val_acc = val_corrects / len(ds_val)
        epoch_val_f1 = f1_score(val_labels_all, val_preds_all, average="macro", zero_division=0)

        # Catat History
        history["train_loss"].append(epoch_train_loss)
        history["val_loss"].append(epoch_val_loss)
        history["train_acc"].append(epoch_train_acc)
        history["val_acc"].append(epoch_val_acc)
        history["train_f1"].append(epoch_train_f1)
        history["val_f1"].append(epoch_val_f1)

        elapsed = time.time() - t0
        print(f"Epoch {epoch:02d}/{EPOCHS:02d} [{elapsed:.1f}s] - Train Loss: {epoch_train_loss:.4f} Acc: {epoch_train_acc*100:.1f}% F1: {epoch_train_f1:.4f} | Val Loss: {epoch_val_loss:.4f} Acc: {epoch_val_acc*100:.1f}% F1: {epoch_val_f1:.4f}")

        if epoch_val_f1 > best_val_f1 or best_model_weights is None:
            best_val_f1 = epoch_val_f1
            best_model_weights = model.state_dict().copy()

    # --- TEST PHASE DENGAN MODEL TERBAIK ---
    model.load_state_dict(best_model_weights)
    model.eval()

    test_preds, test_labels, test_probs = [], [], []
    with torch.no_grad():
        for inputs, labels in test_loader:
            inputs, labels = inputs.to(DEVICE), labels.to(DEVICE)
            outputs = model(inputs)
            probs = torch.softmax(outputs, dim=1)
            _, preds = torch.max(outputs, 1)
            
            test_preds.extend(preds.cpu().numpy())
            test_labels.extend(labels.cpu().numpy())
            test_probs.extend(probs.cpu().numpy())

    acc = np.mean(np.array(test_preds) == np.array(test_labels))
    macro_f1 = f1_score(test_labels, test_preds, average="macro", zero_division=0)
    precisions, recalls, f1s, supports = precision_recall_fscore_support(test_labels, test_preds, labels=[0, 1, 2], zero_division=0)

    # Class 2 adalah Grade_C
    recall_grade_c = recalls[2] if len(recalls) > 2 else 0.0

    print(f"\n📊 HASIL EVALUASI [{experiment_name}]:")
    print(f"  ├─ Test Accuracy   : {acc * 100:.2f}%")
    print(f"  ├─ Macro F1-Score  : {macro_f1:.4f}")
    print(f"  └─ RECALL GRADE C  : {recall_grade_c:.4f} (Safety Critical)")
    print("\nClassification Report:")
    print(classification_report(test_labels, test_preds, target_names=GRADE_ORDER, digits=4, zero_division=0))

    metrics_dict = {
        "acc": acc, "macro_f1": macro_f1, "recall_grade_c": recall_grade_c,
        "precisions": precisions, "recalls": recalls, "f1s": f1s
    }

    return model, metrics_dict, test_preds, test_labels, test_probs, history

# %% [markdown]
# # 7. Menjalankan Eksperimen Dual-Split & FFE Cross-Validation

# %%
# Eksperimen 1: Random Split (Baseline)
model_rand, metrics_rand, preds_rand, labels_rand, probs_rand, history_rand = train_and_evaluate(
    train_df_rand, val_df_rand, test_df_rand, experiment_name="Random Split (70/15/15)"
)

# Eksperimen 2: Grouped Split (by Day & Session)
model_group, metrics_group, preds_group, labels_group, probs_group, history_group = train_and_evaluate(
    train_df_group, val_df_group, test_df_group, experiment_name="Grouped Split (by Day/Session)"
)

# Eksperimen 3: Secondary Validation pada Dataset FFE
ffe_preds, ffe_labels, ffe_probs, ffe_metrics = [], [], [], {}
if len(df_ffe) > 0:
    print(f"\n========================================================")
    print(f" SECONDARY VALIDATION ON FFE (CROSS-SPECIES & MACRO EYE)")
    print(f"========================================================")

    ds_ffe = FastRAMFishDataset(df_ffe, eval_transform, desc="FFE Secondary Test")
    ffe_loader = DataLoader(ds_ffe, batch_size=BATCH_SIZE, shuffle=False, num_workers=NUM_WORKERS)

    model_rand.eval()
    with torch.no_grad():
        for inputs, labels in ffe_loader:
            inputs, labels = inputs.to(DEVICE), labels.to(DEVICE)
            outputs = model_rand(inputs)
            probs = torch.softmax(outputs, dim=1)
            _, preds = torch.max(outputs, 1)
            ffe_preds.extend(preds.cpu().numpy())
            ffe_labels.extend(labels.cpu().numpy())
            ffe_probs.extend(probs.cpu().numpy())

    ffe_acc = np.mean(np.array(ffe_preds) == np.array(ffe_labels))
    ffe_f1 = f1_score(ffe_labels, ffe_preds, average="macro", zero_division=0)
    p_f, r_f, f_f, _ = precision_recall_fscore_support(ffe_labels, ffe_preds, labels=[0, 1, 2], zero_division=0)
    ffe_recall_c = r_f[2] if len(r_f) > 2 else 0.0

    ffe_metrics = {"acc": ffe_acc, "macro_f1": ffe_f1, "recall_grade_c": ffe_recall_c}
    print(f"FFE Cross-Species Test -> Accuracy: {ffe_acc * 100:.2f}% | Macro F1: {ffe_f1:.4f} | Recall Grade C: {ffe_recall_c:.4f}")
    print(classification_report(ffe_labels, ffe_preds, target_names=GRADE_ORDER, digits=4, zero_division=0))

# %% [markdown]
# # 8. Visualisasi Evaluasi Komprehensif
# Menyimpan seluruh kurva training, confusion matrix perbandingan, dan grid prediksi ke dalam file gambar.

# %%
def plot_training_history_comparison(h_rand: dict, h_group: dict, out_dir: Path):
    """Visualisasi kurva perbandingan loss, akurasi, dan F1 score per epoch."""
    epochs_range = range(1, len(h_rand["train_loss"]) + 1)
    fig, axes = plt.subplots(1, 3, figsize=(18, 5))
    fig.suptitle("NusaQC Model 1: Training & Validation Curves Comparison", fontsize=15, fontweight="bold")

    # 1. Loss Curve
    axes[0].plot(epochs_range, h_rand["train_loss"], "b--", label="Rand Train Loss")
    axes[0].plot(epochs_range, h_rand["val_loss"], "b-", label="Rand Val Loss", linewidth=2)
    axes[0].plot(epochs_range, h_group["train_loss"], "r--", label="Group Train Loss")
    axes[0].plot(epochs_range, h_group["val_loss"], "r-", label="Group Val Loss", linewidth=2)
    axes[0].set_title("CrossEntropy Loss per Epoch", fontweight="bold")
    axes[0].set_xlabel("Epoch")
    axes[0].set_ylabel("Loss")
    axes[0].legend()

    # 2. Accuracy Curve
    axes[1].plot(epochs_range, [a * 100 for a in h_rand["train_acc"]], "b--", label="Rand Train Acc")
    axes[1].plot(epochs_range, [a * 100 for a in h_rand["val_acc"]], "b-", label="Rand Val Acc", linewidth=2)
    axes[1].plot(epochs_range, [a * 100 for a in h_group["train_acc"]], "r--", label="Group Train Acc")
    axes[1].plot(epochs_range, [a * 100 for a in h_group["val_acc"]], "r-", label="Group Val Acc", linewidth=2)
    axes[1].set_title("Accuracy (%) per Epoch", fontweight="bold")
    axes[1].set_xlabel("Epoch")
    axes[1].set_ylabel("Accuracy (%)")
    axes[1].legend()

    # 3. Macro F1 Curve
    axes[2].plot(epochs_range, h_rand["train_f1"], "b--", label="Rand Train F1")
    axes[2].plot(epochs_range, h_rand["val_f1"], "b-", label="Rand Val F1", linewidth=2)
    axes[2].plot(epochs_range, h_group["train_f1"], "r--", label="Group Train F1")
    axes[2].plot(epochs_range, h_group["val_f1"], "r-", label="Group Val F1", linewidth=2)
    axes[2].set_title("Macro F1-Score per Epoch", fontweight="bold")
    axes[2].set_xlabel("Epoch")
    axes[2].set_ylabel("Macro F1")
    axes[2].legend()

    plt.tight_layout()
    curves_path = out_dir / "training_curves_comparison.png"
    plt.savefig(curves_path, dpi=300)
    plt.show()
    print(f"📈 Kurva training tersimpan: {curves_path}")

def plot_comprehensive_confusion_matrices(lbl_rand, prd_rand, lbl_grp, prd_grp, lbl_ffe, prd_ffe, out_dir: Path):
    """Plot matriks kebingungan (raw count dan normalized) untuk ketiga pengujian."""
    n_cols = 3 if len(lbl_ffe) > 0 else 2
    fig, axes = plt.subplots(2, n_cols, figsize=(6 * n_cols, 10))
    fig.suptitle("NusaQC Model 1: Confusion Matrices (Raw Counts vs Normalized %)", fontsize=16, fontweight="bold")

    experiments = [
        ("Random Split (Baseline)", lbl_rand, prd_rand),
        ("Grouped Split (Honest)", lbl_grp, prd_grp)
    ]
    if len(lbl_ffe) > 0:
        experiments.append(("FFE Secondary Test", lbl_ffe, prd_ffe))

    for idx, (title, y_true, y_pred) in enumerate(experiments):
        cm = confusion_matrix(y_true, y_pred, labels=[0, 1, 2])
        cm_norm = cm.astype('float') / (cm.sum(axis=1)[:, np.newaxis] + 1e-6) * 100

        # Baris 1: Raw Counts
        sns.heatmap(cm, annot=True, fmt="d", cmap="Blues", cbar=False, ax=axes[0, idx],
                    xticklabels=GRADE_ORDER, yticklabels=GRADE_ORDER, annot_kws={"size": 12, "weight": "bold"})
        axes[0, idx].set_title(f"{title}\n[Raw Counts]", fontsize=12, fontweight="bold")
        axes[0, idx].set_ylabel("True Grade" if idx == 0 else "")
        axes[0, idx].set_xlabel("Predicted Grade")

        # Baris 2: Normalized %
        sns.heatmap(cm_norm, annot=True, fmt=".1f", cmap="Greens", cbar=False, ax=axes[1, idx],
                    xticklabels=GRADE_ORDER, yticklabels=GRADE_ORDER, annot_kws={"size": 12, "weight": "bold"})
        axes[1, idx].set_title(f"{title}\n[Normalized %]", fontsize=12, fontweight="bold")
        axes[1, idx].set_ylabel("True Grade" if idx == 0 else "")
        axes[1, idx].set_xlabel("Predicted Grade")

    plt.tight_layout()
    cm_path = out_dir / "confusion_matrices_all.png"
    plt.savefig(cm_path, dpi=300)
    plt.show()
    print(f"🎯 Confusion matrices tersimpan: {cm_path}")

def plot_sample_prediction_grid(test_df: pd.DataFrame, preds: list, probs: list, out_dir: Path, n_samples: int = 12):
    """Menampilkan grid citra uji dengan perbandingan prediksi benar vs misklasifikasi."""
    fig, axes = plt.subplots(3, 4, figsize=(16, 12))
    fig.suptitle("NusaQC Model 1: Sampel Visual Hasil Prediksi Test Set (DaFiF)", fontsize=15, fontweight="bold")
    axes = axes.flatten()

    sample_indices = random.sample(range(len(test_df)), min(n_samples, len(test_df)))
    for ax_idx, sample_idx in enumerate(sample_indices):
        row = test_df.iloc[sample_idx]
        actual_grade = row["grade"]
        pred_idx = preds[sample_idx]
        pred_grade = REVERSE_GRADE_MAP[pred_idx]
        confidence = probs[sample_idx][pred_idx] * 100

        is_correct = (actual_grade == pred_grade)
        status_color = "#27AE60" if is_correct else "#C0392B"
        status_text = "CORRECT" if is_correct else "MISCLASSIFIED"

        ax = axes[ax_idx]
        try:
            img = Image.open(row["filepath"]).convert("RGB")
            ax.imshow(img)
        except Exception:
            pass

        title_str = f"Pred: {pred_grade} ({confidence:.1f}%)\nTrue: {actual_grade} | {status_text}"
        ax.set_title(title_str, fontsize=10, fontweight="bold", color=status_color)
        ax.axis("off")

    plt.tight_layout()
    preds_grid_path = out_dir / "sample_test_predictions_grid.png"
    plt.savefig(preds_grid_path, dpi=300)
    plt.show()
    print(f"🖼️ Sample predictions grid tersimpan: {preds_grid_path}")

plot_training_history_comparison(history_rand, history_group, OUTPUT_DIR)
plot_comprehensive_confusion_matrices(labels_rand, preds_rand, labels_group, preds_group, ffe_labels, ffe_preds, OUTPUT_DIR)
plot_sample_prediction_grid(test_df_rand, preds_rand, probs_rand, OUTPUT_DIR, n_samples=12)

# %% [markdown]
# # 9. Robust ONNX Export (Opset 17) & Dynamic INT8 Quantization
# - Mengekspor bobot model PyTorch ke **ONNX Float32** menggunakan `opset_version=17` yang stabil di PyTorch 2.x tanpa error `onnxscript` / Dynamo.
# - Mengaplikasikan **Dynamic INT8 Quantization** dengan operator selection yang tepat untuk deployment edge device (Raspberry Pi 5).

# %%
print(f"\n========================================================")
print(f" EXPORTING BEST MODEL TO ONNX & INT8 QUANTIZATION")
print(f"========================================================")

# Simpan bobot PyTorch asli terlebih dahulu
pt_path = OUTPUT_DIR / "mobilenetv3_freshness.pt"
torch.save(model_rand.state_dict(), pt_path)
pt_size_mb = pt_path.stat().st_size / (1024 * 1024)
print(f"1. PyTorch Weights Saved   : {pt_path} ({pt_size_mb:.2f} MB)")

# Siapkan model di CPU untuk ONNX Export
model_rand.eval()
model_rand.to("cpu")
dummy_input = torch.randn(1, 3, 224, 224, device="cpu")

onnx_fp32_path = OUTPUT_DIR / "mobilenetv3_freshness.onnx"
onnx_int8_path = OUTPUT_DIR / "mobilenetv3_freshness_int8.onnx"

# Ekspor ONNX Float32 menggunakan TorchScript Tracing (100% stabil, bypass Dynamo/onnxscript)
try:
    traced_model = torch.jit.trace(model_rand, dummy_input)
    torch.onnx.export(
        traced_model,
        dummy_input,
        str(onnx_fp32_path),
        export_params=True,
        opset_version=14,
        do_constant_folding=True,
        input_names=["input"],
        output_names=["output"],
        dynamic_axes={"input": {0: "batch_size"}, "output": {0: "batch_size"}}
    )
    # Validasi model ONNX
    onnx_model = onnx.load(str(onnx_fp32_path))
    onnx.checker.check_model(onnx_model)
    fp32_size_mb = onnx_fp32_path.stat().st_size / (1024 * 1024)
    print(f"2. ONNX Float32 Exported   : {onnx_fp32_path} ({fp32_size_mb:.2f} MB) [TorchScript Traced, Opset 14]")
except Exception as e:
    print(f"Direct export error: {e}. Mencoba export standar...")
    try:
        torch.onnx.export(
            model_rand,
            dummy_input,
            str(onnx_fp32_path),
            export_params=True,
            opset_version=14,
            do_constant_folding=True
        )
        fp32_size_mb = onnx_fp32_path.stat().st_size / (1024 * 1024)
        print(f"2. ONNX Float32 (Fallback) : {onnx_fp32_path} ({fp32_size_mb:.2f} MB)")
    except Exception as e2:
        print(f"ONNX export gagal: {e2}")

# Dynamic INT8 Quantization (Target MatMul & Gemm untuk Classifier)
if onnx_fp32_path.exists():
    try:
        quantize_dynamic(
            model_input=str(onnx_fp32_path),
            model_output=str(onnx_int8_path),
            weight_type=QuantType.QUInt8,
            op_types_to_quantize=["MatMul", "Gemm"]
        )
        int8_size_mb = onnx_int8_path.stat().st_size / (1024 * 1024)
        compression_ratio = (1 - (int8_size_mb / fp32_size_mb)) * 100
        print(f"3. ONNX INT8 Quantized     : {onnx_int8_path} ({int8_size_mb:.2f} MB) [Kompresi: {compression_ratio:.1f}%]")
    except Exception as e:
        print(f"Catatan Kuantisasi ONNX Dynamic: {e}")
        # Fallback quantize dasar
        try:
            quantize_dynamic(
                model_input=str(onnx_fp32_path),
                model_output=str(onnx_int8_path),
                weight_type=QuantType.QUInt8
            )
            int8_size_mb = onnx_int8_path.stat().st_size / (1024 * 1024)
            print(f"3. ONNX INT8 Quantized (Fallback) : {onnx_int8_path} ({int8_size_mb:.2f} MB)")
        except Exception as e2:
            print(f"Quantization gagal: {e2}")

# %% [markdown]
# # 10. Edge CPU Inference Latency Benchmark
# Mengukur performa komputasi (latensi per frame & throughput FPS) pada mode CPU untuk membuktikan kesiapan deployment pada edge microcomputer (Raspberry Pi 5).

# %%
print(f"\n========================================================")
print(f" BENCHMARKING CPU INFERENCE LATENCY (EDGE SIMULATION)")
print(f"========================================================")

dummy_np = np.random.randn(1, 3, 224, 224).astype(np.float32)
dummy_tensor = torch.from_numpy(dummy_np).to("cpu")

WARMUP_RUNS = 50
TIMED_RUNS = 200

# 1. PyTorch CPU Benchmark
model_rand.eval()
model_rand.to("cpu")
with torch.no_grad():
    for _ in range(WARMUP_RUNS):
        _ = model_rand(dummy_tensor)
    t_start = time.time()
    for _ in range(TIMED_RUNS):
        _ = model_rand(dummy_tensor)
    pytorch_cpu_ms = ((time.time() - t_start) / TIMED_RUNS) * 1000

# 2. ONNX Runtime FP32 CPU Benchmark
ort_sess_fp32 = ort.InferenceSession(str(onnx_fp32_path), providers=["CPUExecutionProvider"])
input_name_fp32 = ort_sess_fp32.get_inputs()[0].name
for _ in range(WARMUP_RUNS):
    _ = ort_sess_fp32.run(None, {input_name_fp32: dummy_np})
t_start = time.time()
for _ in range(TIMED_RUNS):
    _ = ort_sess_fp32.run(None, {input_name_fp32: dummy_np})
ort_fp32_ms = ((time.time() - t_start) / TIMED_RUNS) * 1000

# 3. ONNX Runtime INT8 CPU Benchmark
ort_int8_ms = 0.0
if onnx_int8_path.exists():
    try:
        ort_sess_int8 = ort.InferenceSession(str(onnx_int8_path), providers=["CPUExecutionProvider"])
        input_name_int8 = ort_sess_int8.get_inputs()[0].name
        for _ in range(WARMUP_RUNS):
            _ = ort_sess_int8.run(None, {input_name_int8: dummy_np})
        t_start = time.time()
        for _ in range(TIMED_RUNS):
            _ = ort_sess_int8.run(None, {input_name_int8: dummy_np})
        ort_int8_ms = ((time.time() - t_start) / TIMED_RUNS) * 1000
    except Exception as e:
        print(f"Error benchmark INT8: {e}")

print(f"\n📊 HASIL BENCHMARK LATENSI CPU (Batch Size = 1):")
print(f"  ├─ 1. PyTorch CPU Native   : {pytorch_cpu_ms:.2f} ms/frame ({1000/pytorch_cpu_ms:.1f} FPS)")
print(f"  ├─ 2. ONNX Runtime FP32    : {ort_fp32_ms:.2f} ms/frame ({1000/ort_fp32_ms:.1f} FPS)")
if ort_int8_ms > 0:
    print(f"  └─ 3. ONNX Runtime INT8    : {ort_int8_ms:.2f} ms/frame ({1000/ort_int8_ms:.1f} FPS)")

# %% [markdown]
# # 11. Final Summary Table untuk Submisi Proposal COMPFEST 18

# %%
print(f"\n" + "=" * 70)
print(f" ⭐ RINGKASAN DATA AKHIR MODEL 1 (NUSAQC FRESHNESS ENGINE)")
print(f"=" * 70)

summary_rows = [
    {"Metode Evaluasi": "Random Split (Baseline)", "Akurasi (%)": f"{metrics_rand['acc']*100:.2f}%", "Macro F1": f"{metrics_rand['macro_f1']:.4f}", "Recall Grade C": f"{metrics_rand['recall_grade_c']:.4f}", "Status": "Artificially Inflated (Leakage)"},
    {"Metode Evaluasi": "Grouped Split (Honest)", "Akurasi (%)": f"{metrics_group['acc']*100:.2f}%", "Macro F1": f"{metrics_group['macro_f1']:.4f}", "Recall Grade C": f"{metrics_group['recall_grade_c']:.4f}", "Status": "Production Generalization"},
]
if len(df_ffe) > 0 and "acc" in ffe_metrics:
    summary_rows.append({"Metode Evaluasi": "FFE Secondary Test", "Akurasi (%)": f"{ffe_metrics['acc']*100:.2f}%", "Macro F1": f"{ffe_metrics['macro_f1']:.4f}", "Recall Grade C": f"{ffe_metrics['recall_grade_c']:.4f}", "Status": "Domain/Modality Mismatch"})

df_summary = pd.DataFrame(summary_rows)
print(df_summary.to_string(index=False))

print(f"\n📦 MODEL ARTIFACT SIZES & LATENCY:")
print(f"  ├─ PyTorch Weight (.pt)    : {pt_size_mb:.2f} MB")
print(f"  ├─ ONNX FP32 (.onnx)       : {fp32_size_mb:.2f} MB | Latensi: {ort_fp32_ms:.2f} ms")
if onnx_int8_path.exists() and ort_int8_ms > 0:
    print(f"  └─ ONNX INT8 (.onnx)       : {int8_size_mb:.2f} MB | Latensi: {ort_int8_ms:.2f} ms")

print(f"\n📂 Seluruh artefak visual (.png) & model (.onnx) tersimpan di: {OUTPUT_DIR.resolve()}")
print("=" * 70)
