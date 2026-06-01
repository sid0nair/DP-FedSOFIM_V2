"""
Federated dataset loading with chenyaofo CIFAR-pretrained backbones.

Supported backbones (all from chenyaofo/pytorch-cifar-models):
  CIFAR-10  pretrained: resnet20, resnet32, resnet44, resnet56
  CIFAR-100 pretrained: cifar100_resnet20, cifar100_resnet56
"""

import torch
import torch.nn as nn
try:
    import medmnist
    from medmnist import INFO
except ImportError:
    medmnist = None
    INFO = None
import os
# Use Drive cache for medmnist if available
if os.path.exists('/content/drive/MyDrive/medmnist_cache'):
    os.environ['MEDMNIST_HOME'] = '/content/drive/MyDrive/medmnist_cache'

# ============================================================================
# CIFAR-10 NATIVE PRETRAINED MODELS (RECOMMENDED - 92-94% baseline!)
# ============================================================================

def get_cifar10_resnet20_features(device='cuda'):
    """
    ResNet-20 pretrained on CIFAR-10 (chenyaofo/pytorch-cifar-models)

    Baseline accuracy: 92.52%
    Feature dimension: 64
    Expected FL accuracy: 75-80%

    BEST FOR: Fast training, memory-efficient
    """
    print("=" * 80)
    print("Loading CIFAR-10 Pretrained ResNet-20")
    print("=" * 80)

    try:
        model = torch.hub.load(
            "chenyaofo/pytorch-cifar-models",
            "cifar10_resnet20",
            pretrained=True,
            trust_repo=True
        )
        print("✅ Loaded CIFAR-10 pretrained ResNet-20")

        # Extract feature extractor (remove final FC layer)
        feature_extractor = nn.Sequential(*list(model.children())[:-1])
        feature_extractor.add_module('flatten', nn.Flatten())

        # Freeze all parameters
        feature_extractor.eval()
        for param in feature_extractor.parameters():
            param.requires_grad = False

        print("✅ Feature extractor ready!")
        print("📊 Baseline accuracy: 92.52%")
        print("   Feature dimension: 64")
        print("=" * 80)

        return feature_extractor.to(device)

    except Exception as e:
        print(f"❌ Error loading CIFAR-10 ResNet-20: {e}")
        raise


def get_cifar10_resnet32_features(device='cuda'):
    """
    ResNet-32 pretrained on CIFAR-10 (chenyaofo/pytorch-cifar-models)

    Baseline accuracy: 93.46%
    Feature dimension: 64
    Expected FL accuracy: 75-82%

    BEST FOR: Balance of accuracy and speed
    """
    print("=" * 80)
    print("Loading CIFAR-10 Pretrained ResNet-32")
    print("=" * 80)

    try:
        model = torch.hub.load(
            "chenyaofo/pytorch-cifar-models",
            "cifar10_resnet32",
            pretrained=True,
            trust_repo=True
        )
        print("✅ Loaded CIFAR-10 pretrained ResNet-32")

        # Extract feature extractor (remove final FC layer)
        feature_extractor = nn.Sequential(*list(model.children())[:-1])
        feature_extractor.add_module('flatten', nn.Flatten())

        # Freeze all parameters
        feature_extractor.eval()
        for param in feature_extractor.parameters():
            param.requires_grad = False

        print("✅ Feature extractor ready!")
        print("📊 Baseline accuracy: 93.46%")
        print("   Feature dimension: 64")
        print("   Expected FL accuracy: 75-82%")
        print("=" * 80)

        return feature_extractor.to(device)

    except Exception as e:
        print(f"❌ Error loading CIFAR-10 ResNet-32: {e}")
        raise


def get_cifar10_resnet56_features(device='cuda'):
    """
    ResNet-56 pretrained on CIFAR-10 (chenyaofo/pytorch-cifar-models)

    Baseline accuracy: 94.36% ⭐ BEST!
    Feature dimension: 64
    Expected FL accuracy: 78-85%

    BEST FOR: Maximum accuracy (RECOMMENDED!)
    """
    print("=" * 80)
    print("Loading CIFAR-10 Pretrained ResNet-56 (BEST MODEL!)")
    print("=" * 80)

    try:
        model = torch.hub.load(
            "chenyaofo/pytorch-cifar-models",
            "cifar10_resnet56",
            pretrained=True,
            trust_repo=True
        )
        print("✅ Loaded CIFAR-10 pretrained ResNet-56")

        # Extract feature extractor (remove final FC layer)
        feature_extractor = nn.Sequential(*list(model.children())[:-1])
        feature_extractor.add_module('flatten', nn.Flatten())

        # Freeze all parameters
        feature_extractor.eval()
        for param in feature_extractor.parameters():
            param.requires_grad = False

        print("✅ Feature extractor ready!")
        print("📊 Baseline accuracy: 94.36% ⭐")
        print("   Feature dimension: 64")
        print("   Expected FL accuracy: 78-85%")
        print("=" * 80)

        return feature_extractor.to(device)

    except Exception as e:
        print(f"❌ Error loading CIFAR-10 ResNet-56: {e}")
        raise


def get_cifar10_resnet44_features(device='cuda'):
    """
    ResNet-44 pretrained on CIFAR-10 (chenyaofo/pytorch-cifar-models)

    Baseline accuracy: ~93.8%
    Feature dimension: 64
    Expected FL accuracy: 76-83%
    """
    print("=" * 80)
    print("Loading CIFAR-10 Pretrained ResNet-44")
    print("=" * 80)

    try:
        model = torch.hub.load(
            "chenyaofo/pytorch-cifar-models",
            "cifar10_resnet44",
            pretrained=True,
            trust_repo=True
        )
        print("✅ Loaded CIFAR-10 pretrained ResNet-44")

        # Extract feature extractor (remove final FC layer)
        feature_extractor = nn.Sequential(*list(model.children())[:-1])
        feature_extractor.add_module('flatten', nn.Flatten())

        # Freeze all parameters
        feature_extractor.eval()
        for param in feature_extractor.parameters():
            param.requires_grad = False

        print("✅ Feature extractor ready!")
        print("📊 Baseline accuracy: ~93.8%")
        print("   Feature dimension: 64")
        print("   Expected FL accuracy: 76-83%")
        print("=" * 80)

        return feature_extractor.to(device)

    except Exception as e:
        print(f"❌ Error loading CIFAR-10 ResNet-44: {e}")
        raise


def get_cifar100_resnet56_features(device='cuda'):
    """
    ResNet-56 pretrained on CIFAR-100.

    This matches the paper's setup (Table 3) for Transfer Learning.
    - Trained on: CIFAR-100 (100 classes)
    - Applied to: CIFAR-10 (10 classes)
    - Feature Dim: 64

    Expected Accuracy: High (likely ~85-90%) and robust.
    """
    print("=" * 80)
    print("Loading CIFAR-100 Pretrained ResNet-56")
    print("=" * 80)

    try:
        # Note the model name: 'cifar100_resnet56'
        model = torch.hub.load(
            "chenyaofo/pytorch-cifar-models",
            "cifar100_resnet56",
            pretrained=True,
            trust_repo=True
        )
        print("✅ Loaded CIFAR-100 pretrained ResNet-56")

        # Remove final FC layer (which would be 100 classes)
        feature_extractor = nn.Sequential(*list(model.children())[:-1])
        feature_extractor.add_module('flatten', nn.Flatten())

        # Freeze
        feature_extractor.eval()
        for param in feature_extractor.parameters():
            param.requires_grad = False

        return feature_extractor.to(device)

    except Exception as e:
        print(f"❌ Error loading CIFAR-100 ResNet-56: {e}")
        raise


def get_cifar100_resnet20_features(device='cuda'):
    """ResNet-20 pretrained on CIFAR-100."""
    print("=" * 80)
    print("Loading CIFAR-100 Pretrained ResNet-20")
    print("=" * 80)
    try:
        model = torch.hub.load("chenyaofo/pytorch-cifar-models", "cifar100_resnet20", pretrained=True, trust_repo=True)
        feature_extractor = nn.Sequential(*list(model.children())[:-1])
        feature_extractor.add_module('flatten', nn.Flatten())
        feature_extractor.eval()
        for param in feature_extractor.parameters():
            param.requires_grad = False
        return feature_extractor.to(device)
    except Exception as e:
        print(f"❌ Error: {e}")
        raise

def get_vit_features(device='cuda', model_name='vit_base_patch16_224'):
    """
    ViT pretrained on ImageNet via timm.
    Returns feature extractor and feature_dim.
    Feature dim: 768 (vit_base), 384 (vit_small).
    Input: 224×224 RGB images.
    """
    try:
        import timm
    except ImportError:
        raise ImportError("ViT backbone requires timm. Run: pip install timm")

    print(f"\n{'='*80}\nLoading ViT: {model_name}\n{'='*80}")
    model = timm.create_model(model_name, pretrained=True, num_classes=0)
    # num_classes=0 → returns CLS token (768-dim) directly, no head
    model.eval()
    for param in model.parameters():
        param.requires_grad = False
    return model.to(torch.device(device))

# ============================================================================
# FEDERATED DATASET HELPERS
# ============================================================================

import torch
import torch.nn as nn
from torch.utils.data import Dataset, DataLoader, Subset
from torchvision import datasets, transforms
import numpy as np
from typing import List, Tuple, Dict, Optional


# ============================================================================
# FEDERATED DATASET HELPERS
# ============================================================================

class FeatureDataset(Dataset):
    """Dataset that holds pre-extracted features and labels"""

    def __init__(self, features: torch.Tensor, labels: torch.Tensor):
        self.features = features
        self.labels = labels

    def __len__(self):
        return len(self.features)

    def __getitem__(self, idx):
        return self.features[idx], self.labels[idx]


def partition_data_iid(dataset, num_clients: int, seed: int = 42) -> List[List[int]]:
    """
    Partition dataset indices in an IID manner across clients.

    Args:
        dataset: PyTorch dataset
        num_clients: Number of clients
        seed: Random seed

    Returns:
        List of index lists, one per client
    """
    np.random.seed(seed)
    n_samples = len(dataset)
    indices = np.random.permutation(n_samples)

    # Split indices equally among clients
    client_indices = np.array_split(indices, num_clients)
    return [idx.tolist() for idx in client_indices]


def partition_data_non_iid_classes(dataset, num_clients: int,
                                   classes_per_client: int = 2,
                                   seed: int = 42) -> List[List[int]]:
    """
    Partition dataset so each client only has data from a few classes (non-IID).
    Each class's samples are sharded disjointly across the clients that own it,
    so no sample appears in more than one client.

    Args:
        dataset: list of (_, label) tuples (already-extracted label list)
        num_clients: Number of clients
        classes_per_client: How many classes each client gets
        seed: Random seed

    Returns:
        List of index lists, one per client
    """
    np.random.seed(seed)

    # Group indices by class
    class_indices = {}
    for idx, (_, label) in enumerate(dataset):
        if label not in class_indices:
            class_indices[label] = []
        class_indices[label].append(idx)

    num_classes = len(class_indices)

    # Build class assignment: for each class, decide which clients own it.
    # We do a round-robin shard assignment so that every client gets
    # exactly classes_per_client classes and every class is owned by
    # roughly (num_clients * classes_per_client / num_classes) clients.
    classes = list(range(num_classes))
    np.random.shuffle(classes)

    # Map: class -> list of client ids that own it
    class_to_clients = {c: [] for c in classes}
    # Assign classes to clients in round-robin so each client gets exactly
    # classes_per_client classes.
    client_class_count = [0] * num_clients
    # Build a flat list of (client_id) slots: each client needs classes_per_client slots
    slots = []
    for client_id in range(num_clients):
        slots.extend([client_id] * classes_per_client)
    np.random.shuffle(slots)

    # Assign each class to one slot (one client); cycle through classes
    # We need len(slots) == num_clients * classes_per_client assignments.
    # Each class gets floor(num_clients * classes_per_client / num_classes) owners.
    class_to_clients = {c: [] for c in range(num_classes)}
    for slot_idx, client_id in enumerate(slots):
        cls = classes[slot_idx % num_classes]
        class_to_clients[cls].append(client_id)

    client_indices = [[] for _ in range(num_clients)]

    # For each class, shard its samples disjointly among owning clients
    for cls, owners in class_to_clients.items():
        if not owners:
            continue
        cls_idx = np.array(class_indices[cls])
        np.random.shuffle(cls_idx)
        shards = np.array_split(cls_idx, len(owners))
        for client_id, shard in zip(owners, shards):
            client_indices[client_id].extend(shard.tolist())

    # Shuffle each client's indices
    for idx_list in client_indices:
        np.random.shuffle(idx_list)

    return client_indices


def partition_data_dirichlet(dataset, num_clients: int,
                             alpha: float = 0.5,
                             seed: int = 42,
                             min_samples_per_client: int = 2) -> List[List[int]]:
    """
    Partition dataset using Dirichlet distribution (non-IID with varying degrees).

    Args:
        dataset: list of (_, label) tuples
        num_clients: Number of clients
        alpha: Dirichlet concentration parameter (lower = more heterogeneous)
        seed: Random seed
        min_samples_per_client: Minimum samples guaranteed per client.
            Clients that end up below this threshold receive samples
            redistributed from the largest clients until all clients
            meet the minimum.

    Returns:
        List of index lists, one per client
    """
    np.random.seed(seed)

    # Group indices by class
    class_indices = {}
    for idx, (_, label) in enumerate(dataset):
        if label not in class_indices:
            class_indices[label] = []
        class_indices[label].append(idx)

    num_classes = len(class_indices)
    client_indices = [[] for _ in range(num_clients)]

    # For each class, distribute samples to clients using Dirichlet
    for cls in range(num_classes):
        cls_idx = np.array(class_indices[cls])
        np.random.shuffle(cls_idx)

        # Sample proportions from Dirichlet distribution
        proportions = np.random.dirichlet([alpha] * num_clients)

        # Split indices according to proportions
        split_points = (np.cumsum(proportions) * len(cls_idx)).astype(int)[:-1]
        splits = np.split(cls_idx, split_points)

        for client_id, split in enumerate(splits):
            client_indices[client_id].extend(split.tolist())

    # Enforce minimum samples per client by redistributing from largest clients
    for _ in range(num_clients * 2):  # iterate until stable
        sizes = [len(c) for c in client_indices]
        deficient = [i for i, s in enumerate(sizes) if s < min_samples_per_client]
        if not deficient:
            break
        donor = int(np.argmax(sizes))
        for client_id in deficient:
            needed = min_samples_per_client - len(client_indices[client_id])
            if len(client_indices[donor]) - needed < min_samples_per_client:
                break
            transfer = client_indices[donor][-needed:]
            client_indices[donor] = client_indices[donor][:-needed]
            client_indices[client_id].extend(transfer)

    # Shuffle each client's indices
    for idx_list in client_indices:
        np.random.shuffle(idx_list)

    return client_indices


def extract_features_from_dataset(dataset, feature_extractor, device, batch_size=128):
    """
    Extract features from a dataset using a frozen feature extractor.

    Args:
        dataset: PyTorch dataset
        feature_extractor: Frozen feature extraction model
        device: Device to run on
        batch_size: Batch size for extraction

    Returns:
        Tuple of (features, labels) as tensors
    """
    loader = DataLoader(dataset, batch_size=batch_size, shuffle=False,
                        num_workers=2, pin_memory=True)

    features_list = []
    labels_list = []

    feature_extractor.eval()
    with torch.no_grad():
        for images, labels in loader:
            images = images.to(device)
            feats = feature_extractor(images)
            features_list.append(feats.cpu())
            labels_list.append(labels)

    features = torch.cat(features_list, dim=0)
    labels = torch.cat(labels_list, dim=0)

    return features, labels

# ============================================================================
# MAIN FEDERATED DATA LOADING FUNCTIONS
# ============================================================================

def get_federated_cifar10_feature_loaders(
        data_dir: str = "./data",
        num_clients: int = 20,
        batch_size: int = 64,
        device: str = "cuda",
        partition_type: str = "iid",
        alpha: float = 0.5,
        classes_per_client: int = 2,
        min_samples_per_client: int = 10,
        seed: int = 42,
        num_workers: int = 2,
        pin_memory: bool = True,
        backbone: str = "resnet56",
        resize_to_224: Optional[bool] = None
) -> Tuple[List[DataLoader], DataLoader, int, Dict]:
    """
    Create federated CIFAR-10 feature loaders for multiple clients.

    Args:
        data_dir: Directory to store CIFAR-10 data
        num_clients: Number of federated clients
        batch_size: Batch size for training
        device: Device for feature extraction
        partition_type: One of 'iid', 'non_iid_classes', 'dirichlet'
        alpha: Dirichlet concentration parameter
        classes_per_client: Number of classes per client (for non_iid_classes)
        min_samples_per_client: Minimum samples per client
        seed: Random seed
        num_workers: DataLoader workers
        pin_memory: Pin memory for DataLoader
        backbone: Which backbone to use
        resize_to_224: Whether to resize to 224x224 (for ImageNet models)

    Returns:
        Tuple of (client_loaders, test_loader, feature_dim, partition_stats)
    """
    print(f"\n{'=' * 80}")
    print(f"Creating Federated CIFAR-10 Dataset")
    print(f"{'=' * 80}")
    print(f"Clients: {num_clients}")
    print(f"Partition: {partition_type}")
    print(f"Backbone: {backbone}")

    # All supported backbones are chenyaofo CIFAR-style (32x32 input), never resize.
    resize_to_224 = False

    # Setup transforms
    if resize_to_224:
        transform = transforms.Compose([
            transforms.Resize(224),
            transforms.ToTensor(),
            transforms.Normalize((0.4914, 0.4822, 0.4465),
                                 (0.2023, 0.1994, 0.2010))
        ])
    else:
        transform = transforms.Compose([
            transforms.ToTensor(),
            transforms.Normalize((0.4914, 0.4822, 0.4465),
                                 (0.2023, 0.1994, 0.2010))
        ])

    # Load CIFAR-10
    trainset = datasets.CIFAR10(root=data_dir, train=True,
                                download=True, transform=transform)
    testset = datasets.CIFAR10(root=data_dir, train=False,
                               download=True, transform=transform)

    print(f"Loaded CIFAR-10: {len(trainset)} train, {len(testset)} test samples")

    # Load feature extractor
    device_obj = torch.device(device)

    if backbone == "resnet20":
        feature_extractor = get_cifar10_resnet20_features(device)
    elif backbone == "resnet32":
        feature_extractor = get_cifar10_resnet32_features(device)
    elif backbone == "resnet44":
        feature_extractor = get_cifar10_resnet44_features(device)
    elif backbone == "resnet56":
        feature_extractor = get_cifar10_resnet56_features(device)
    elif backbone == "cifar100_resnet56":
        feature_extractor = get_cifar100_resnet56_features(device)
    elif backbone == "cifar100_resnet20":
        feature_extractor = get_cifar100_resnet20_features(device)
    elif backbone == "vit_base":
        return get_vit_features(device, 'vit_base_patch16_224'), 768
    elif backbone == "vit_small":
        return get_vit_features(device, 'vit_small_patch16_224'), 384
    else:
        raise ValueError(
            f"Unknown backbone: {backbone}. "
            f"Supported: resnet20/32/44/56, cifar100_resnet20/56, vit_base, vit_small")

        # Extract features
    print(f"\nExtracting features from training set...")
    train_features, train_labels = extract_features_from_dataset(
        trainset, feature_extractor, device_obj, batch_size=128
    )

    print(f"Extracting features from test set...")
    test_features, test_labels = extract_features_from_dataset(
        testset, feature_extractor, device_obj, batch_size=128
    )

    feature_dim = train_features.shape[1]
    print(f"✅ Feature extraction complete! Dimension: {feature_dim}")

    # Partition data across clients
    print(f"\nPartitioning data across {num_clients} clients...")

    # Create a temporary dataset for partitioning
    temp_dataset = [(None, label.item()) for label in train_labels]

    if partition_type == "iid":
        client_indices = partition_data_iid(temp_dataset, num_clients, seed)
    elif partition_type == "non_iid_classes":
        client_indices = partition_data_non_iid_classes(
            temp_dataset, num_clients, classes_per_client, seed
        )
    elif partition_type == "dirichlet":
        client_indices = partition_data_dirichlet(
            temp_dataset, num_clients, alpha, seed
        )
    else:
        raise ValueError(f"Unknown partition type: {partition_type}")

    # Create client datasets and loaders
    client_loaders = []
    partition_stats = {
        'num_clients': num_clients,
        'partition_type': partition_type,
        'client_sizes': [],
        'client_class_distributions': []
    }

    for client_id, indices in enumerate(client_indices):
        # Create feature dataset for this client
        client_features = train_features[indices]
        client_labels = train_labels[indices]

        client_dataset = FeatureDataset(client_features, client_labels)
        client_loader = DataLoader(
            client_dataset,
            batch_size=batch_size,
            shuffle=True,
            num_workers=0,  # Features already in memory
            pin_memory=False
        )

        client_loaders.append(client_loader)

        # Track statistics
        partition_stats['client_sizes'].append(len(indices))

        # Class distribution
        unique, counts = torch.unique(client_labels, return_counts=True)
        class_dist = {int(k): int(v) for k, v in zip(unique, counts)}
        partition_stats['client_class_distributions'].append(class_dist)

        print(f"  Client {client_id}: {len(indices)} samples, "
              f"classes: {list(class_dist.keys())}")

    # Create global test loader
    test_dataset = FeatureDataset(test_features, test_labels)
    test_loader = DataLoader(
        test_dataset,
        batch_size=batch_size,
        shuffle=False,
        num_workers=0,
        pin_memory=False
    )

    print(f"✅ Federated dataset created successfully!")
    print(f"{'=' * 80}\n")

    return client_loaders, test_loader, feature_dim, partition_stats


def get_federated_cifar10_binary_features(
        data_dir: str = "./data",
        num_clients: int = 20,
        batch_size: int = 64,
        device: str = "cuda",
        class_0: int = 0,
        class_1: int = 1,
        partition_type: str = "iid",
        alpha: float = 0.5,
        classes_per_client: int = 2,
        seed: int = 42,
        num_workers: int = 2,
        pin_memory: bool = True,
        backbone: str = "resnet56",
        resize_to_224: Optional[bool] = None
) -> Tuple[List[DataLoader], DataLoader, int, Dict]:
    """
    Create federated CIFAR-10 binary classification dataset.

    Similar to get_federated_cifar10_feature_loaders but for binary classification.
    """
    print(f"\n{'=' * 80}")
    print(f"Creating Federated CIFAR-10 Binary Dataset")
    print(f"{'=' * 80}")
    print(f"Classes: {class_0} vs {class_1}")

    # Get full dataset first
    client_loaders, test_loader, feature_dim, partition_stats = \
        get_federated_cifar10_feature_loaders(
            data_dir=data_dir,
            num_clients=num_clients,
            batch_size=batch_size,
            device=device,
            partition_type=partition_type,
            alpha=alpha,
            classes_per_client=classes_per_client,
            seed=seed,
            num_workers=num_workers,
            pin_memory=pin_memory,
            backbone=backbone,
            resize_to_224=resize_to_224
        )

    # Filter for binary classes and convert labels to 0/1
    binary_client_loaders = []

    for client_loader in client_loaders:
        dataset = client_loader.dataset

        # Filter for binary classes
        mask = (dataset.labels == class_0) | (dataset.labels == class_1)
        binary_features = dataset.features[mask]
        binary_labels = dataset.labels[mask]

        # Convert to 0/1
        binary_labels = (binary_labels == class_1).float()

        binary_dataset = FeatureDataset(binary_features, binary_labels)
        binary_loader = DataLoader(
            binary_dataset,
            batch_size=batch_size,
            shuffle=True,
            num_workers=0,
            pin_memory=False
        )

        binary_client_loaders.append(binary_loader)

    # Filter test set
    test_dataset = test_loader.dataset
    mask = (test_dataset.labels == class_0) | (test_dataset.labels == class_1)
    binary_test_features = test_dataset.features[mask]
    binary_test_labels = test_dataset.labels[mask]
    binary_test_labels = (binary_test_labels == class_1).float()

    binary_test_dataset = FeatureDataset(binary_test_features, binary_test_labels)
    binary_test_loader = DataLoader(
        binary_test_dataset,
        batch_size=batch_size,
        shuffle=False,
        num_workers=0,
        pin_memory=False
    )

    print(f"✅ Binary dataset created!")
    print(f"{'=' * 80}\n")

    return binary_client_loaders, binary_test_loader, feature_dim, partition_stats

def get_federated_chestmnist_features(
        num_clients: int = 20,
        batch_size: int = 64,
        device: str = 'cuda',
        partition_type: str = 'iid',
        alpha: float = 0.5,
        classes_per_client: int = 2,
        seed: int = 42,
        num_workers: int = 2,
        pin_memory: bool = True,
        backbone: str = 'cifar100_resnet20',
        target_label_name: str = 'Pneumonia'
) -> Tuple[List[DataLoader], DataLoader, int, int, Dict]:
    """Create federated loaders using ChestMNIST as the dataset.

    This is a drop-in analogue of get_federated_cifar10_feature_loaders, but:
    - Uses MedMNIST v2 ChestMNIST (grayscale, 28x28).
    - Uses a 1-channel ResNet-18 feature extractor by default.
    - Converts the original multi-hot labels into single-label multi-class IDs:
        class 0      -> Normal (no disease)
        class 1..C   -> index of first positive disease in the vector
    """
    if medmnist is None or INFO is None:
        raise ImportError(
            "medmnist is not installed. Please run 'pip install medmnist' to use ChestMNIST."
        )

    print("\n" + "=" * 80)
    print("Creating Federated ChestMNIST Dataset (multi-class medical setup)")
    print("=" * 80)
    print(f"Clients: {num_clients}")
    print(f"Partition: {partition_type}")
    print(f"Backbone: {backbone}")
    print("=" * 80)

    # -----------------------------------------------------------------------
    # 1. Load ChestMNIST
    # -----------------------------------------------------------------------
    data_flag = 'chestmnist'
    info = INFO[data_flag]
    DataClass = getattr(medmnist, info['python_class'])

    # Convert grayscale to 3-channel so CIFAR-pretrained backbone can process it.
    # Resize to 32x32 to match the CIFAR backbone's expected input resolution.
    transform = transforms.Compose([
        transforms.Resize(32),
        transforms.Grayscale(num_output_channels=3),
        transforms.ToTensor(),
        transforms.Normalize((0.4914, 0.4822, 0.4465), (0.2023, 0.1994, 0.2010))
    ])

    train_dataset = DataClass(split='train', transform=transform, download=True)
    test_dataset = DataClass(split='test', transform=transform, download=True)

    print(f"Loaded ChestMNIST: {len(train_dataset)} train, {len(test_dataset)} test samples")

    # -----------------------------------------------------------------------
    # 2. Build feature extractor
    # -----------------------------------------------------------------------
    device_obj = torch.device(device)
    feature_extractor, feature_dim_backbone = _select_cifar_style_feature_extractor(backbone, device)

    # -----------------------------------------------------------------------
    # 3. Extract features from train and test sets
    # -----------------------------------------------------------------------
    print("\nExtracting features from ChestMNIST training set...")
    train_features, train_labels = extract_features_from_dataset(
        train_dataset, feature_extractor, device_obj, batch_size=128
    )

    print("Extracting features from ChestMNIST test set...")
    test_features, test_labels = extract_features_from_dataset(
        test_dataset, feature_extractor, device_obj, batch_size=128
    )

    # -----------------------------------------------------------------------
    # 4. Convert labels to CIFAR-style single-label multi-class IDs
    # -----------------------------------------------------------------------
    # ChestMNIST labels are typically multi-hot [N, C]. We convert them to:
    #   0           -> Normal (no disease)
    #   1..C        -> index of FIRST positive disease
    if train_labels.ndim == 2:
        train_labels_raw = train_labels.long()
        test_labels_raw = test_labels.long()

        num_labels = train_labels_raw.size(1)

        def multi_hot_to_single(y_raw: torch.Tensor) -> torch.Tensor:
            sums = y_raw.sum(dim=1)
            normal_mask = (sums == 0)
            disease_idx = torch.argmax(y_raw, dim=1) + 1  # 1..num_labels
            y_single = disease_idx.clone()
            y_single[normal_mask] = 0
            return y_single

        train_labels_single = multi_hot_to_single(train_labels_raw)
        test_labels_single = multi_hot_to_single(test_labels_raw)
        num_classes = num_labels + 1  # 0 = Normal
    elif train_labels.ndim == 1:
        # Already single-label classes (just ensure long type)
        train_labels_single = train_labels.long()
        test_labels_single = test_labels.long()
        num_classes = int(train_labels_single.max().item()) + 1
    else:
        raise ValueError(f"Unexpected ChestMNIST label shape: {train_labels.shape}")

    feature_dim = train_features.shape[1]
    print(f"✅ Feature extraction complete! Dimension: {feature_dim}")
    print(f"Detected {num_classes} classes (0 = Normal, 1.. = diseases)")

    # -----------------------------------------------------------------------
    # 5. Partition training data across clients
    # -----------------------------------------------------------------------
    print(f"\nPartitioning ChestMNIST data across {num_clients} clients...")

    # Temporary dataset for partitioning: list of scalar integer labels
    temp_dataset = [(None, int(label.item())) for label in train_labels_single]

    if partition_type == 'iid':
        client_indices = partition_data_iid(temp_dataset, num_clients, seed)
    elif partition_type == 'non_iid_classes':
        client_indices = partition_data_non_iid_classes(
            temp_dataset, num_clients, classes_per_client, seed
        )
    elif partition_type == 'dirichlet':
        client_indices = partition_data_dirichlet(
            temp_dataset, num_clients, alpha, seed
        )
    else:
        raise ValueError(f"Unknown partition type: {partition_type}")

    # -----------------------------------------------------------------------
    # 6. Create client feature datasets and loaders
    # -----------------------------------------------------------------------
    client_loaders: List[DataLoader] = []
    partition_stats: Dict = {
        'num_clients': num_clients,
        'partition_type': partition_type,
        'client_sizes': [],
        'client_class_distributions': []
    }

    for client_id, indices in enumerate(client_indices):
        client_features = train_features[indices]
        client_labels = train_labels_single[indices]

        client_dataset = FeatureDataset(client_features, client_labels)
        client_loader = DataLoader(
            client_dataset,
            batch_size=batch_size,
            shuffle=True,
            num_workers=0,
            pin_memory=False
        )
        client_loaders.append(client_loader)

        # Stats
        partition_stats['client_sizes'].append(len(indices))
        unique, counts = torch.unique(client_labels, return_counts=True)
        class_dist = {int(k): int(v) for k, v in zip(unique, counts)}
        partition_stats['client_class_distributions'].append(class_dist)

        print(f"  Client {client_id}: {len(indices)} samples, class distribution: {class_dist}")

    # -----------------------------------------------------------------------
    # 7. Global test loader
    # -----------------------------------------------------------------------
    test_dataset_features = FeatureDataset(test_features, test_labels_single)
    test_loader = DataLoader(
        test_dataset_features,
        batch_size=batch_size,
        shuffle=False,
        num_workers=0,
        pin_memory=False
    )

    print("✅ Federated ChestMNIST dataset created successfully (multi-class)!")
    print("=" * 80 + "\n")

    # Return num_classes so train.py can treat ChestMNIST like CIFAR-10 multi-class
    return client_loaders, test_loader, feature_dim, num_classes, partition_stats


# =========================================================================
# MEDMNIST RGB DATASETS (PATHMNIST / BLOODMNIST / DERMAMNIST) – CIFAR PIPELINE
# =========================================================================

def _select_cifar_style_feature_extractor(backbone: str, device: str):
    """Select a chenyaofo CIFAR-pretrained feature extractor."""
    if backbone == "resnet20":
        return get_cifar10_resnet20_features(device)
    elif backbone == "resnet32":
        return get_cifar10_resnet32_features(device)
    elif backbone == "resnet44":
        return get_cifar10_resnet44_features(device)
    elif backbone == "resnet56":
        return get_cifar10_resnet56_features(device)
    elif backbone == "cifar100_resnet56":
        return get_cifar100_resnet56_features(device)
    elif backbone == "cifar100_resnet20":
        return get_cifar100_resnet20_features(device)
    else:
        raise ValueError(f"Unknown backbone: {backbone}. Supported: resnet20/32/44/56, cifar100_resnet20/56")


def get_federated_medmnist_rgb_features(
        data_flag: str = "pathmnist",
        num_clients: int = 20,
        batch_size: int = 64,
        device: str = "cuda",
        partition_type: str = "iid",
        alpha: float = 0.5,
        classes_per_client: int = 2,
        seed: int = 42,
        num_workers: int = 2,
        pin_memory: bool = True,
        backbone: str = "cifar100_resnet20",
        feature_extract_batch_size: int = 128,
        resize_to: int = 32,
        use_cifar_norm: bool = True,
) -> Tuple[List[DataLoader], DataLoader, int, int, Dict]:
    """Create federated feature loaders for MedMNIST *RGB* datasets.

    This is designed to plug directly into your existing CIFAR-style pipeline:
    - Uses 32x32 RGB inputs (Resize to 32).
    - Uses your CIFAR-pretrained ResNet-20/56 feature extractors.
    - Keeps labels as standard single-label multi-class IDs.

    Recommended `data_flag` values:
      - 'pathmnist' (9 classes, RGB)
      - 'bloodmnist' (8 classes, RGB)
      - 'dermamnist' (7 classes, RGB)

    Returns:
      (client_loaders, test_loader, feature_dim, num_classes, partition_stats)
    """
    if medmnist is None or INFO is None:
        raise ImportError(
            "medmnist is not installed. Please run 'pip install medmnist' to use MedMNIST datasets."
        )

    if data_flag not in INFO:
        raise ValueError(f"Unknown MedMNIST data_flag: {data_flag}. Available: {list(INFO.keys())}")

    info = INFO[data_flag]
    DataClass = getattr(medmnist, info['python_class'])

    # Hard requirement for 'drop-in' CIFAR pipeline: RGB input
    n_channels = int(info.get('n_channels', 3))
    if n_channels != 3:
        raise ValueError(
            f"{data_flag} has n_channels={n_channels}. Use an RGB MedMNIST dataset (e.g., pathmnist/bloodmnist/dermamnist) "
            "for direct compatibility with CIFAR-style backbones."
        )

    # Standard CIFAR normalization (keeps CIFAR-pretrained features well-behaved)
    if use_cifar_norm:
        mean = (0.4914, 0.4822, 0.4465)
        std = (0.2023, 0.1994, 0.2010)
    else:
        # Fallback normalization if you want dataset-agnostic scaling
        mean = (0.5, 0.5, 0.5)
        std = (0.5, 0.5, 0.5)

    # ViT requires 224×224, CIFAR backbones use 32×32
    input_size = 224 if backbone.startswith('vit') else resize_to
    # Use ImageNet normalization for ViT, CIFAR norm for CIFAR backbones
    if backbone.startswith('vit'):
        mean = (0.485, 0.456, 0.406)
        std = (0.229, 0.224, 0.225)
    transform = transforms.Compose([
        transforms.Resize((input_size, input_size)),
        transforms.ToTensor(),
        transforms.Normalize(mean, std)
    ])

    print("\n" + "=" * 80)
    print(f"Creating Federated MedMNIST RGB Dataset: {data_flag}")
    print("=" * 80)
    print(f"Clients: {num_clients}")
    print(f"Partition: {partition_type}")
    print(f"Backbone: {backbone}")
    print(f"Resize: {input_size}x{input_size}")
    print(f"Norm: {'CIFAR' if use_cifar_norm else '0.5/0.5'}")
    print("=" * 80)

    train_dataset = DataClass(split='train', transform=transform, download=True)
    test_dataset = DataClass(split='test', transform=transform, download=True)

    print(f"Loaded {data_flag}: {len(train_dataset)} train, {len(test_dataset)} test samples")

    # Build feature extractor
    device_obj = torch.device(device)
    feature_extractor = _select_cifar_style_feature_extractor(backbone, device)

    # Extract features
    extract_bs = 32 if backbone.startswith('vit') else feature_extract_batch_size
    train_features, train_labels = extract_features_from_dataset(
        train_dataset, feature_extractor, device_obj, batch_size=extract_bs
    )
    test_features, test_labels = extract_features_from_dataset(
        test_dataset, feature_extractor, device_obj, batch_size=extract_bs
    )

    # MedMNIST labels are typically shape [N, 1] (or sometimes [N])
    if train_labels.ndim == 2 and train_labels.size(1) == 1:
        train_labels = train_labels.squeeze(1)
    if test_labels.ndim == 2 and test_labels.size(1) == 1:
        test_labels = test_labels.squeeze(1)

    train_labels = train_labels.long()
    test_labels = test_labels.long()

    num_classes = int(info.get('n_classes', int(train_labels.max().item()) + 1))

    feature_dim = train_features.shape[1]
    print(f"✅ Feature extraction complete! Dimension: {feature_dim}")
    print(f"✅ Num classes: {num_classes}")

    # Partition training data across clients
    print(f"\nPartitioning {data_flag} data across {num_clients} clients...")
    temp_dataset = [(None, int(label.item())) for label in train_labels]

    if partition_type == "iid":
        client_indices = partition_data_iid(temp_dataset, num_clients, seed)
    elif partition_type == "non_iid_classes":
        client_indices = partition_data_non_iid_classes(
            temp_dataset, num_clients, classes_per_client, seed
        )
    elif partition_type == "dirichlet":
        client_indices = partition_data_dirichlet(
            temp_dataset, num_clients, alpha, seed
        )
    else:
        raise ValueError(f"Unknown partition type: {partition_type}")

    # Create client datasets and loaders
    client_loaders: List[DataLoader] = []
    partition_stats: Dict = {
        'num_clients': num_clients,
        'partition_type': partition_type,
        'client_sizes': [],
        'client_class_distributions': []
    }

    for client_id, indices in enumerate(client_indices):
        client_features = train_features[indices]
        client_labels = train_labels[indices]

        client_dataset = FeatureDataset(client_features, client_labels)
        client_loader = DataLoader(
            client_dataset,
            batch_size=batch_size,
            shuffle=True,
            num_workers=0,
            pin_memory=False
        )
        client_loaders.append(client_loader)

        partition_stats['client_sizes'].append(len(indices))
        unique, counts = torch.unique(client_labels, return_counts=True)
        class_dist = {int(k): int(v) for k, v in zip(unique, counts)}
        partition_stats['client_class_distributions'].append(class_dist)

        print(f"  Client {client_id}: {len(indices)} samples, classes: {list(class_dist.keys())}")

    # Global test loader
    test_dataset_features = FeatureDataset(test_features, test_labels)
    test_loader = DataLoader(
        test_dataset_features,
        batch_size=batch_size,
        shuffle=False,
        num_workers=0,
        pin_memory=False
    )

    print(f"✅ Federated {data_flag} dataset created successfully!")
    print("=" * 80 + "\n")

    return client_loaders, test_loader, feature_dim, num_classes, partition_stats


# Convenience wrappers (most drop-in for your pipeline)

def get_federated_pathmnist_features(**kwargs):
    return get_federated_medmnist_rgb_features(data_flag='pathmnist', **kwargs)


def get_federated_bloodmnist_features(**kwargs):
    return get_federated_medmnist_rgb_features(data_flag='bloodmnist', **kwargs)


def get_federated_dermamnist_features(**kwargs):
    return get_federated_medmnist_rgb_features(data_flag='dermamnist', **kwargs)