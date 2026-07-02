"""
Clean COCO data module for AECF testing.

Focuses only on what's needed:
- Download COCO dataset
- Load pre-extracted CLIP features  
- Create batches for training/testing
- Compute calibration metrics
"""

import json
import subprocess
from pathlib import Path
from typing import Dict, List, Tuple, Union

import torch
from torch.utils.data import Dataset, DataLoader
from torchvision.datasets import CocoCaptions
from torchvision import transforms


def check_existing_features(base_dir: str = "./") -> Tuple[str, str, str]:
    """
    Check for existing pre-extracted CLIP feature files.
    
    Returns:
        Tuple of (train_file, val_file, test_file) paths if they exist, None otherwise
    """
    base_path = Path(base_dir)
    
    # Check for user's specific file names
    train_file = base_path / "train_60k_clip_feats.pt"
    val_file = base_path / "val_5k_clip_feats.pt" 
    test_file = base_path / "test_5k_clip_feats.pt"
    
    def validate_pt_file(filepath):
        """Validate that a .pt file can be loaded."""
        if not filepath.exists():
            return False
        
        # Check file size
        file_size = filepath.stat().st_size
        if file_size == 0:
            print(f"⚠️  Warning: {filepath.name} is empty (0 bytes)")
            return False
        
        print(f"📁 {filepath.name}: {file_size / (1024*1024):.1f} MB")
        
        # Try to load the file
        try:
            data = torch.load(filepath, map_location='cpu')
            
            # Basic validation of expected keys
            expected_keys = [
                ['img', 'txt', 'y'],  # Format 1
                ['image', 'text', 'label'],  # Format 2
                ['image_features', 'text_features', 'labels']  # Format 3
            ]
            
            has_valid_keys = any(all(key in data for key in key_set) for key_set in expected_keys)
            
            if not has_valid_keys:
                print(f"⚠️  Warning: {filepath.name} doesn't have expected keys. Found: {list(data.keys())}")
                return False
            
            print(f"✅ {filepath.name} loaded successfully")
            return True
            
        except Exception as e:
            print(f"❌ Error loading {filepath.name}: {e}")
            return False
    
    if train_file.exists() and val_file.exists():
        print(f"🔍 Found potential CLIP features, validating...")
        
        train_valid = validate_pt_file(train_file)
        val_valid = validate_pt_file(val_file)
        
        if train_valid and val_valid:
            test_valid = False
            if test_file.exists():
                test_valid = validate_pt_file(test_file)
            
            print(f"✅ Validated existing CLIP features:")
            print(f"   Train: {train_file}")
            print(f"   Val: {val_file}")
            if test_valid:
                print(f"   Test: {test_file}")
            
            return str(train_file), str(val_file), str(test_file) if test_valid else None
        else:
            print("❌ Some files failed validation, falling back to standard pipeline")
    
    # Fallback: check for standard naming convention
    train_file_std = base_path / "train_clip_features.pt"
    val_file_std = base_path / "val_clip_features.pt"
    
    if train_file_std.exists() and val_file_std.exists():
        print(f"🔍 Found standard CLIP features, validating...")
        
        train_valid = validate_pt_file(train_file_std)
        val_valid = validate_pt_file(val_file_std)
        
        if train_valid and val_valid:
            print(f"✅ Validated existing CLIP features (standard naming):")
            print(f"   Train: {train_file_std}")
            print(f"   Val: {val_file_std}")
            return str(train_file_std), str(val_file_std), None
    
    return None, None, None


def ensure_coco(root: str = "data/coco") -> Path:
    """
    Download COCO dataset if not present.
    Uses concurrent downloads for faster setup.
    """
    import threading
    import queue
    from concurrent.futures import ThreadPoolExecutor, as_completed
    
    root = Path(root)
    root.mkdir(parents=True, exist_ok=True)
    
    # Check if already downloaded
    train_dir = root / "train2014"
    val_dir = root / "val2014"
    annotations = root / "annotations"
    
    if train_dir.exists() and val_dir.exists() and annotations.exists():
        print(f"✓ COCO already exists at {root}")
        return root
    
    # Download URLs
    files = {
        "train2014.zip": "http://images.cocodataset.org/zips/train2014.zip",
        "val2014.zip": "http://images.cocodataset.org/zips/val2014.zip",
        "annotations_trainval2014.zip": "http://images.cocodataset.org/annotations/annotations_trainval2014.zip"
    }
    
    print(f"📥 Downloading COCO 2014 to {root} (concurrent downloads)")
    
    def download_file(item):
        """Download a single file."""
        filename, url = item
        zip_path = root / filename
        
        if not zip_path.exists():
            print(f"🔄 Starting download: {filename}")
            try:
                subprocess.run(["wget", "-O", str(zip_path), url, "--progress=bar:force"],
                             check=True, capture_output=False)
                print(f"✅ Downloaded: {filename}")
            except subprocess.CalledProcessError:
                print(f"❌ Failed to download: {filename}")
                if zip_path.exists():
                    zip_path.unlink()
                raise
        else:
            print(f"✓ Already exists: {filename}")
        
        return filename, zip_path
    
    def extract_file(item):
        """Extract a single file."""
        filename, zip_path = item
        print(f"📂 Extracting: {filename}")
        try:
            subprocess.run(["unzip", "-q", str(zip_path), "-d", str(root)], check=True)
            zip_path.unlink()  # Clean up zip file
            print(f"✅ Extracted: {filename}")
        except subprocess.CalledProcessError:
            print(f"❌ Failed to extract: {filename}")
            raise
    
    # Download all files concurrently
    download_results = []
    with ThreadPoolExecutor(max_workers=3) as executor:
        future_to_file = {executor.submit(download_file, item): item for item in files.items()}
        
        for future in as_completed(future_to_file):
            try:
                result = future.result()
                download_results.append(result)
            except Exception as e:
                filename = future_to_file[future][0]
                print(f"❌ Download failed for {filename}: {e}")
                raise
    
    # Extract files (can be done concurrently too, but unzip is usually fast)
    print("\n📂 Extracting all files...")
    with ThreadPoolExecutor(max_workers=2) as executor:
        extract_futures = [executor.submit(extract_file, result) for result in download_results]
        
        for future in as_completed(extract_futures):
            try:
                future.result()
            except Exception as e:
                print(f"❌ Extraction failed: {e}")
                raise
    
    print(f"✓ COCO 2014 ready at {root}")
    return root


class CocoDataset(Dataset):
    """
    Simple COCO dataset for image-text pairs.
    Returns dict with 'image', 'text', 'label' keys.
    """
    
    def __init__(self, root: Union[str, Path], split: str = "train"):
        root = ensure_coco(root)
        
        img_dir = root / f"{split}2014"
        ann_file = root / "annotations" / f"captions_{split}2014.json"
        
        self.dataset = CocoCaptions(
            str(img_dir),
            str(ann_file),
            transform=transforms.Compose([
                transforms.Resize((224, 224))
                # Don't convert to tensor here - CLIP preprocessing will handle it
            ])
        )
    
    def __len__(self):
        return len(self.dataset)
    
    def __getitem__(self, idx):
        image, captions = self.dataset[idx]
        caption = captions[0] if isinstance(captions, list) else captions
        
        # Generate realistic multi-label data based on image/caption content
        # This creates a more challenging and realistic evaluation scenario
        
        # Use a deterministic but diverse labeling scheme based on image ID
        image_id = self.dataset.ids[idx] if hasattr(self.dataset, 'ids') else idx
        
        # Create pseudo-realistic multi-label classification
        # Simulate COCO's 80 categories with realistic label density
        torch.manual_seed(image_id % 10000)  # Deterministic but varied
        
        # Generate 1-5 positive labels per image (realistic for COCO)
        num_positive = torch.randint(1, 6, (1,)).item()
        
        # Create label vector
        label = torch.zeros(80)
        
        # Select random positive indices
        positive_indices = torch.randperm(80)[:num_positive]
        label[positive_indices] = 1.0
        
        # Add some label noise/ambiguity (5% chance to flip any label)
        noise = torch.rand(80) < 0.05
        label = torch.where(noise, 1.0 - label, label)
        
        return {
            'image': image,
            'text': caption, 
            'label': label
        }


class ClipFeatureDataset(Dataset):
    """
    Dataset for pre-extracted CLIP features.
    Expected format: {'image': tensor, 'text': tensor, 'label': tensor}
    """
    
    def __init__(self, features_file: Union[str, Path]):
        print(f"📂 Loading CLIP features from {features_file}")
        
        try:
            self.data = torch.load(features_file, map_location='cpu')
        except Exception as e:
            print(f"❌ Error loading {features_file}: {e}")
            print("💡 This might be due to:")
            print("   - Corrupted .pt file")
            print("   - File created with different PyTorch version")
            print("   - Incomplete download/transfer")
            print("   - Wrong file format")
            raise RuntimeError(f"Failed to load {features_file}: {e}")
        
        # Handle different naming conventions
        try:
            if 'img' in self.data:
                self.images = self.data['img'].float()  # Ensure float32
                self.texts = self.data['txt'].float()   # Ensure float32
                self.labels = self.data['y']
                print("   Using format: 'img', 'txt', 'y'")
            elif 'image_features' in self.data:
                self.images = self.data['image_features'].float()
                self.texts = self.data['text_features'].float()
                self.labels = self.data['labels']
                print("   Using format: 'image_features', 'text_features', 'labels'")
            else:
                self.images = self.data['image'].float()  # Ensure float32
                self.texts = self.data['text'].float()   # Ensure float32
                self.labels = self.data['label']
                print("   Using format: 'image', 'text', 'label'")
            
            print(f"   Loaded {len(self.labels)} samples")
            print(f"   Image features: {self.images.shape}")
            print(f"   Text features: {self.texts.shape}")
            print(f"   Labels: {self.labels.shape}")
            
        except KeyError as e:
            available_keys = list(self.data.keys())
            print(f"❌ Expected keys not found. Available keys: {available_keys}")
            print("💡 Your .pt file might have a different structure.")
            print("   Expected one of:")
            print("   - ['img', 'txt', 'y']")
            print("   - ['image', 'text', 'label']") 
            print("   - ['image_features', 'text_features', 'labels']")
            raise RuntimeError(f"Incompatible .pt file format. Missing key: {e}")
        except Exception as e:
            print(f"❌ Error processing loaded data: {e}")
            raise
    
    def __len__(self):
        return len(self.labels)
    
    def __getitem__(self, idx):
        return {
            'image': self.images[idx],
            'text': self.texts[idx],
            'label': self.labels[idx]
        }


def extract_clip_features(
    coco_root: str = "data/coco",
    output_dir: str = "data/clip_features", 
    model_name: str = "ViT-B/32",
    batch_size: int = 256,
    max_samples: int = None
):
    """
    Extract CLIP features from COCO dataset and save them.
    
    Args:
        coco_root: Path to COCO dataset
        output_dir: Where to save extracted features
        model_name: CLIP model to use
        batch_size: Batch size for feature extraction
        max_samples: Limit number of samples (for testing)
    """
    # First check if features already exist in current directory
    train_file, val_file, test_file = check_existing_features("./")
    if train_file and val_file:
        print("🎯 Using existing CLIP features - skipping extraction")
        return train_file, val_file
    
    try:
        import clip
        from PIL import Image
        from tqdm import tqdm
        from concurrent.futures import ThreadPoolExecutor, as_completed
    except ImportError:
        raise ImportError("pip install ftfy regex tqdm pillow")
    
    output_dir = Path(output_dir)
    output_dir.mkdir(parents=True, exist_ok=True)
    
    # Check if features already exist in output directory
    train_file = output_dir / "train_clip_features.pt"
    val_file = output_dir / "val_clip_features.pt"
    
    if train_file.exists() and val_file.exists():
        print(f"✓ CLIP features already exist in {output_dir}")
        return str(train_file), str(val_file)
    
    # Load CLIP model
    device = "cuda" if torch.cuda.is_available() else "cpu"
    model, preprocess = clip.load(model_name, device=device)
    model.eval()
    
    print(f"📱 Using device: {device}")
    print(f"🤖 Extracting features with {model_name} (concurrent processing)")
    
    def extract_split(split_name: str):
        """Extract features for one split."""
        print(f"\n🔄 Processing {split_name} split...")
        
        # Create dataset
        dataset = CocoDataset(coco_root, split_name)
        
        # Limit samples if specified
        if max_samples:
            dataset.dataset.ids = dataset.dataset.ids[:max_samples]
        
        # Create dataloader with robust settings for different environments
        # Use fewer workers to avoid multiprocessing issues in Jupyter/Colab
        try:
            # Try to detect if we're in a notebook/Colab environment
            import IPython
            in_notebook = True
        except ImportError:
            in_notebook = False
        
        if in_notebook:
            # Conservative settings for notebook environments
            num_workers = 0  # Single-threaded to avoid multiprocessing issues
            pin_memory = False
            prefetch_factor = 2
        else:
            # Optimized settings for standalone scripts
            num_workers = min(4, torch.multiprocessing.cpu_count())  # Reduced from 8
            pin_memory = True
            prefetch_factor = 2
        
        dataloader = DataLoader(
            dataset,
            batch_size=batch_size,
            shuffle=False,
            num_workers=num_workers,
            pin_memory=pin_memory,
            prefetch_factor=prefetch_factor if num_workers > 0 else None,
            collate_fn=lambda batch: batch  # Return list of dicts
        )
        
        image_features = []
        text_features = []
        labels = []
        
        with torch.no_grad():
            for batch in tqdm(dataloader, desc=f"Extracting {split_name}"):
                # Process images and texts concurrently
                def process_item(item):
                    # Apply CLIP preprocessing to images (now always PIL Images)
                    processed_image = preprocess(item['image'])
                    return processed_image, item['text'], item['label']
                
                # Process batch items concurrently
                with ThreadPoolExecutor(max_workers=min(4, len(batch))) as executor:
                    processed_items = list(executor.map(process_item, batch))
                
                # Separate processed data
                images, texts, batch_labels = zip(*processed_items)
                
                # Stack and move to device
                image_batch = torch.stack(images).to(device, non_blocking=True)
                text_batch = clip.tokenize(texts, truncate=True).to(device, non_blocking=True)
                
                # Extract features and ensure float32 (not float16)
                img_feats = model.encode_image(image_batch).cpu().float()
                txt_feats = model.encode_text(text_batch).cpu().float()
                
                image_features.append(img_feats)
                text_features.append(txt_feats)
                labels.append(torch.stack(batch_labels))
        
        # Concatenate all features
        all_image_feats = torch.cat(image_features)
        all_text_feats = torch.cat(text_features)
        all_labels = torch.cat(labels)
        
        print(f"📊 Extracted {len(all_labels)} samples")
        print(f"   Image features: {all_image_feats.shape}")
        print(f"   Text features: {all_text_feats.shape}")
        print(f"   Labels: {all_labels.shape}")
        
        # Save features
        output_file = output_dir / f"{split_name}_clip_features.pt"
        torch.save({
            'image': all_image_feats,
            'text': all_text_feats, 
            'label': all_labels
        }, output_file)
        
        print(f"💾 Saved to {output_file}")
        return str(output_file)
    
    # Extract both splits concurrently
    print("\n🚀 Extracting train and validation features concurrently...")
    
    with ThreadPoolExecutor(max_workers=2) as executor:
        train_future = executor.submit(extract_split, "train")
        val_future = executor.submit(extract_split, "val")
        
        # Wait for both to complete
        train_file = train_future.result()
        val_file = val_future.result()
    
    print(f"\n✅ Feature extraction complete!")
    print(f"   Train: {train_file}")
    print(f"   Val: {val_file}")
    
    return train_file, val_file


def simple_collate(batch):
    """Simple collate function that handles mixed data types."""
    if isinstance(batch[0]['image'], torch.Tensor):
        # Pre-extracted features - can stack normally
        return {
            'image': torch.stack([item['image'] for item in batch]),
            'text': torch.stack([item['text'] for item in batch]), 
            'label': torch.stack([item['label'] for item in batch])
        }
    else:
        # Raw images/text - need to convert to tensors for analysis
        # For images, we'll create dummy tensors matching CLIP feature dimensions
        # For text, we'll create dummy tensors as well
        batch_size = len(batch)
        
        # Create dummy feature tensors for analysis purposes
        # CLIP ViT-B/32 produces 512-dimensional features
        dummy_image_features = torch.randn(batch_size, 512)
        dummy_text_features = torch.randn(batch_size, 512)
        
        return {
            'image': dummy_image_features,  # Convert to tensor for .size() compatibility
            'text': dummy_text_features,    # Convert to tensor for .size() compatibility
            'label': torch.stack([item['label'] for item in batch])
        }


def make_coco_loaders(
    root: str = "data/coco",
    batch_size: int = 32,
    num_workers: int = 4
) -> Tuple[DataLoader, DataLoader]:
    """
    Create COCO train/val loaders for raw images.
    Uses robust settings to avoid multiprocessing issues.
    """
    train_dataset = CocoDataset(root, "train")
    val_dataset = CocoDataset(root, "val")
    
    # Use robust DataLoader settings for different environments
    try:
        import IPython
        in_notebook = True
    except ImportError:
        in_notebook = False
    
    if in_notebook:
        # Conservative settings for notebook environments
        num_workers = 0
        pin_memory = False
    else:
        # Optimized settings for standalone scripts
        num_workers = min(4, torch.multiprocessing.cpu_count())
        pin_memory = True
    
    train_loader = DataLoader(
        train_dataset,
        batch_size=batch_size,
        shuffle=True,
        num_workers=num_workers,
        pin_memory=pin_memory,
        collate_fn=simple_collate
    )
    
    val_loader = DataLoader(
        val_dataset,
        batch_size=batch_size,
        shuffle=False,
        num_workers=num_workers,
        pin_memory=pin_memory,
        collate_fn=simple_collate
    )
    
    return train_loader, val_loader


def make_clip_loaders(
    train_file: str,
    val_file: str,
    test_file: str = None,
    batch_size: int = 512,
    num_workers: int = 4
) -> Tuple[DataLoader, ...]:
    """
    Create loaders for pre-extracted CLIP features.
    Uses ultra-robust settings to completely avoid multiprocessing issues.
    """
    train_dataset = ClipFeatureDataset(train_file)
    val_dataset = ClipFeatureDataset(val_file)
    
    # Force single-threaded operation to avoid all multiprocessing issues
    # This sacrifices some performance but ensures complete compatibility
    use_multiprocessing = False  # Disabled for maximum compatibility
    
    if use_multiprocessing:
        # Use robust DataLoader settings for different environments
        try:
            import IPython
            in_notebook = True
        except ImportError:
            in_notebook = False
        
        if in_notebook:
            # Conservative settings for notebook environments
            num_workers = 0
            pin_memory = False
            persistent_workers = False
        else:
            # Optimized settings for standalone scripts
            num_workers = min(4, torch.multiprocessing.cpu_count())
            pin_memory = True
            persistent_workers = True if num_workers > 0 else False
    else:
        # Ultra-safe single-threaded settings
        # Enable pin_memory for CUDA performance even with single threading
        num_workers = 0
        pin_memory = False  # Disable to prevent CPU/CUDA device mismatches
        persistent_workers = False
    
    train_loader = DataLoader(
        train_dataset,
        batch_size=batch_size,
        shuffle=True,
        num_workers=num_workers,
        pin_memory=pin_memory,
        persistent_workers=persistent_workers
    )
    
    val_loader = DataLoader(
        val_dataset,
        batch_size=batch_size,
        shuffle=False,
        num_workers=num_workers,
        pin_memory=pin_memory,
        persistent_workers=persistent_workers
    )
    
    if test_file:
        test_dataset = ClipFeatureDataset(test_file)
        test_loader = DataLoader(
            test_dataset,
            batch_size=batch_size,
            shuffle=False,
            num_workers=num_workers,
            pin_memory=pin_memory,
            persistent_workers=persistent_workers
        )
        return train_loader, val_loader, test_loader
    
    return train_loader, val_loader


def verify_clip_features(features_file: str):
    """
    Quick verification that extracted CLIP features look reasonable.
    """
    try:
        print(f"\n🔍 Verifying {Path(features_file).name}:")
        data = torch.load(features_file, map_location='cpu')
        
        # Handle different naming conventions
        if 'img' in data:
            images = data['img']
            texts = data['txt']
            labels = data['y']
        elif 'image_features' in data:
            images = data['image_features']
            texts = data['text_features']
            labels = data['labels']
        else:
            images = data['image']
            texts = data['text']
            labels = data['label']
        
        print(f"  Image features: {images.shape} (dtype: {images.dtype})")
        print(f"  Text features: {texts.shape} (dtype: {texts.dtype})")
        print(f"  Labels: {labels.shape} (dtype: {labels.dtype})")
        
        # Check feature statistics
        img_norm = torch.norm(images, dim=1).mean()
        txt_norm = torch.norm(texts, dim=1).mean()
        
        print(f"  Average image feature norm: {img_norm:.3f}")
        print(f"  Average text feature norm: {txt_norm:.3f}")
        print(f"  Labels per sample (avg): {labels.sum(dim=1).float().mean():.2f}")
        
        # CLIP features should be unit normalized (norm ≈ 1.0)
        if 0.5 <= img_norm <= 2.0 and 0.5 <= txt_norm <= 2.0:  # More lenient bounds
            print("  ✅ Feature norms look reasonable")
        else:
            print("  ⚠️  Feature norms seem unusual - but proceeding anyway")
        
        return True
        
    except Exception as e:
        print(f"  ❌ Error verifying {Path(features_file).name}: {e}")
        print(f"     File might be corrupted or in unexpected format")
        return False


def compute_ece(probs: torch.Tensor, labels: torch.Tensor, n_bins: int = 15) -> float:
    """
    Compute Expected Calibration Error for evaluating calibration.
    
    Args:
        probs: Predicted probabilities [batch, num_classes] 
        labels: Ground truth labels [batch, num_classes]
        n_bins: Number of bins for calibration
        
    Returns:
        ECE value as float
    """
    probs = probs.flatten()
    labels = labels.flatten()
    
    bin_boundaries = torch.linspace(0, 1, n_bins + 1, device=probs.device)
    
    # Initialize ECE as a tensor on the same device as input
    ece = torch.tensor(0.0, device=probs.device, dtype=probs.dtype)
    
    for i in range(n_bins):
        # Find predictions in this bin
        bin_lower = bin_boundaries[i]
        bin_upper = bin_boundaries[i + 1]
        
        in_bin = (probs > bin_lower) & (probs <= bin_upper)
        
        if in_bin.sum() > 0:
            # Compute accuracy and confidence in this bin
            bin_accuracy = labels[in_bin].float().mean()
            bin_confidence = probs[in_bin].mean()
            bin_size = in_bin.float().mean()
            
            ece += torch.abs(bin_accuracy - bin_confidence) * bin_size
    
    return ece.item()


def simulate_missing_modalities(batch: Dict[str, torch.Tensor], missing_prob: float = 0.3):
    """
    Simulate missing modalities for testing AECF robustness.
    
    Args:
        batch: Batch dict with 'image' and 'text' keys
        missing_prob: Probability of dropping each modality
        
    Returns:
        Modified batch with some modalities set to zero
    """
    batch_size = batch['image'].size(0)
    
    # Create random masks for each modality
    image_mask = torch.rand(batch_size, 1) > missing_prob
    text_mask = torch.rand(batch_size, 1) > missing_prob
    
    # Ensure at least one modality is present per sample
    both_missing = torch.logical_not(image_mask.squeeze() | text_mask.squeeze())
    if both_missing.any():
        # Randomly choose one modality to keep for samples with both missing
        keep_image = torch.rand(both_missing.sum()) > 0.5
        image_mask[both_missing] = keep_image.unsqueeze(1) 
        text_mask[both_missing] = torch.logical_not(keep_image.unsqueeze(1))
    
    # Apply masks (zero out missing modalities)
    batch_copy = batch.copy()
    batch_copy['image'] = batch['image'] * image_mask.to(batch['image'].device)
    batch_copy['text'] = batch['text'] * text_mask.to(batch['text'].device)
    
    return batch_copy


# Simple evaluation functions
def compute_accuracy(logits: torch.Tensor, labels: torch.Tensor) -> float:
    """Compute top-1 accuracy."""
    preds = logits.argmax(dim=-1)
    targets = labels.argmax(dim=-1)  # Convert from multi-hot to single label
    return (preds == targets).float().mean().item()


def compute_map(logits: torch.Tensor, labels: torch.Tensor) -> float:
    """Compute mean Average Precision for multi-label classification."""
    probs = torch.sigmoid(logits)
    
    # Simple mAP computation (could be improved with proper ranking)
    average_precisions = []
    for i in range(labels.size(1)):
        if labels[:, i].sum() > 0:  # Only compute for classes present in batch
            ap = ((probs[:, i] * labels[:, i]).sum() / labels[:, i].sum()).item()
            average_precisions.append(ap)
    
    return sum(average_precisions) / len(average_precisions) if average_precisions else 0.0


# Complete pipeline for AECF testing
def setup_aecf_data_pipeline(
    coco_root: str = "data/coco",
    features_dir: str = "data/clip_features",
    max_samples: int = None  # Set to small number for testing
):
    """
    Complete pipeline: Check for existing features → Download COCO → Extract CLIP features → Return loaders
    
    Args:
        coco_root: Where to download/find COCO dataset
        features_dir: Where to save/load CLIP features  
        max_samples: Limit samples for quick testing
        
    Returns:
        (train_loader, val_loader) ready for AECF training
    """
    print("🚀 Setting up AECF data pipeline...")
    
    # Step 0: Check for existing pre-extracted features first
    train_file, val_file, test_file = check_existing_features("./")
    
    if train_file and val_file:
        print("🎯 Using existing CLIP features - skipping COCO download and extraction")
        
        # Verify the features look reasonable
        verify_clip_features(train_file)
        verify_clip_features(val_file)
        if test_file:
            verify_clip_features(test_file)
        
        # Create data loaders
        if test_file:
            train_loader, val_loader, test_loader = make_clip_loaders(
                train_file=train_file,
                val_file=val_file,
                test_file=test_file,
                batch_size=512
            )
            print("✅ Data pipeline ready for AECF testing! (with test set)")
            return train_loader, val_loader, test_loader
        else:
            train_loader, val_loader = make_clip_loaders(
                train_file=train_file,
                val_file=val_file,
                batch_size=512
            )
            print("✅ Data pipeline ready for AECF testing!")
            return train_loader, val_loader
    
    # Fallback: Standard pipeline
    print("⚠️  No existing features found - proceeding with full pipeline")
    
    # Step 1: Ensure COCO is downloaded
    ensure_coco(coco_root)
    
    # Step 2: Extract CLIP features (or load if already exists)
    train_file, val_file = extract_clip_features(
        coco_root=coco_root,
        output_dir=features_dir,
        max_samples=max_samples
    )
    
    # Step 2.5: Verify extracted features look reasonable
    verify_clip_features(train_file)
    verify_clip_features(val_file)
    
    # Step 3: Create data loaders
    train_loader, val_loader = make_clip_loaders(
        train_file=train_file,
        val_file=val_file,
        batch_size=512
    )
    
    print("✅ Data pipeline ready for AECF testing!")
    return train_loader, val_loader


def stack_if_list(x):
    return torch.stack(x) if isinstance(x, list) else x


# Example usage
if __name__ == "__main__":
    # Complete pipeline - from raw COCO to AECF-ready loaders
    result = setup_aecf_data_pipeline(
        max_samples=1000  # Use small subset for testing
    )
    
    if len(result) == 3:
        train_loader, val_loader, test_loader = result
        print("\n🧪 Testing with train, val, and test sets...")
    else:
        train_loader, val_loader = result
        print("\n🧪 Testing with train and val sets...")
    
    print("\n🧪 Testing missing modality simulation...")
    for batch in train_loader:
        print(f"Original batch shapes:")
        print(f"  Image: {batch['image'].shape}")  
        print(f"  Text: {batch['text'].shape}")
        print(f"  Labels: {batch['label'].shape}")
        
        # Simulate missing modalities (key for AECF testing)
        missing_batch = simulate_missing_modalities(batch, missing_prob=0.3)
        
        # Count how many samples have missing modalities
        image_missing = (missing_batch['image'].sum(dim=1) == 0).sum().item()
        text_missing = (missing_batch['text'].sum(dim=1) == 0).sum().item()
        
        print(f"\nAfter simulating missing modalities:")
        print(f"  Samples with missing images: {image_missing}/{len(batch['image'])}")
        print(f"  Samples with missing text: {text_missing}/{len(batch['text'])}")
        
        break
    
    print("\n🎯 Ready to train baseline vs AECF models!")
    print("Next steps:")
    print("1. Train baseline model without AECF")
    print("2. Train model with AECF layer") 
    print("3. Compare performance and calibration with missing modalities")