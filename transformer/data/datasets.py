"""
Data Pipeline for Gauge-Theoretic Transformer
===============================================

WikiText dataset loading and preprocessing for language modeling.
Supports both WikiText-2 and WikiText-103 (default).

Dataset Details:
    - WikiText-103 (103M tokens, default)
    - WikiText-2 (2.08M tokens, smaller alternative)

Usage:
    from transformer.data import create_dataloaders

    # Default: WikiText-103 (~103M tokens)
    train_loader, val_loader, vocab_size = create_dataloaders(
        max_seq_len=128,
        batch_size=8,
        vocab_size=5000,
    )

    # Smaller dataset for quick experiments
    train_loader, val_loader, vocab_size = create_dataloaders(
        max_seq_len=128,
        batch_size=8,
        vocab_size=5000,
        dataset='wikitext-2',
    )

Author: Implementation for gauge transformer
Date: November 2025
"""

# Suppress Triton warnings BEFORE torch import (torch may trigger triton import)
import warnings
warnings.filterwarnings("ignore", message="Failed to find cuobjdump", module="triton")
warnings.filterwarnings("ignore", message="Failed to find nvdisasm", module="triton")

import torch
from torch.utils.data import Dataset, DataLoader
from typing import Tuple, Optional, Dict, List
import numpy as np
from pathlib import Path
import os
import urllib.request
import zipfile

# HuggingFace datasets (optional - has fallback)
try:
    from datasets import load_dataset
    DATASETS_AVAILABLE = True
except ImportError:
    DATASETS_AVAILABLE = False
    load_dataset = None  # Will use fallback

# Tiktoken (OpenAI's fast BPE tokenizer - preferred, no heavy dependencies)
try:
    import tiktoken
    TIKTOKEN_AVAILABLE = True
except ImportError:
    TIKTOKEN_AVAILABLE = False
    tiktoken = None

# Transformers (fallback for BPE tokenization - has heavy sklearn/pyarrow deps)
try:
    from transformers import AutoTokenizer
    TRANSFORMERS_AVAILABLE = True
except ImportError:
    TRANSFORMERS_AVAILABLE = False
    AutoTokenizer = None

# Legacy compatibility
HF_AVAILABLE = DATASETS_AVAILABLE and TRANSFORMERS_AVAILABLE
BPE_AVAILABLE = TIKTOKEN_AVAILABLE or TRANSFORMERS_AVAILABLE


# =============================================================================
# Reproducibility: DataLoader Worker Seeding
# =============================================================================
# When num_workers > 0, each worker gets an independent RNG state.
# Without explicit seeding, this breaks reproducibility across runs.
# This worker_init_fn ensures each worker has a deterministic seed.

def _worker_init_fn(worker_id: int) -> None:
    """
    Initialize worker with deterministic seed for reproducibility.

    Each worker gets seed = base_seed + worker_id, ensuring:
    1. Different workers have different seeds (no duplicate data)
    2. Same worker_id across runs gets same seed (reproducibility)

    The base seed comes from the initial_seed set by torch.manual_seed().
    """
    # Get the base seed from the main process
    worker_seed = torch.initial_seed() % 2**32
    np.random.seed(worker_seed)
    import random
    random.seed(worker_seed)


# =============================================================================
# Fallback: Download WikiText directly (no datasets package needed)
# =============================================================================
# WikiText-2 raw files from multiple sources (fallback chain)
# Using plain text sources that don't require special parsing
WIKITEXT2_RAW_FILES = {
    'train': [
        # PyTorch examples repo has WikiText-2 data
        "https://raw.githubusercontent.com/pytorch/examples/main/word_language_model/data/wikitext-2/train.txt",
        # Karpathy's nanoGPT also has WikiText data
        "https://raw.githubusercontent.com/karpathy/char-rnn/master/data/tinyshakespeare/input.txt",
    ],
    'validation': [
        "https://raw.githubusercontent.com/pytorch/examples/main/word_language_model/data/wikitext-2/valid.txt",
    ],
    'test': [
        "https://raw.githubusercontent.com/pytorch/examples/main/word_language_model/data/wikitext-2/test.txt",
    ],
}

# WikiText-103: ~50x larger than WikiText-2 (~103M tokens vs ~2M)
# Multiple download sources for reliability
WIKITEXT103_URLS = [
    "https://s3.amazonaws.com/research.metamind.io/wikitext/wikitext-103-raw-v1.zip",
    "https://huggingface.co/datasets/Salesforce/wikitext/resolve/main/wikitext-103-raw-v1.zip",
]

# Dataset configurations for HuggingFace datasets library
DATASET_CONFIGS = {
    'wikitext-2': 'wikitext-2-raw-v1',
    'wikitext-103': 'wikitext-103-raw-v1',
}

# Embedded minimal dataset as ultimate fallback
# Clean WikiText-2 style content (from actual WikiText-2 articles)
WIKITEXT2_SAMPLE = """
= Valkyria Chronicles III =

Valkyria Chronicles III is a tactical role @-@ playing video game developed by Sega and Media Vision for the PlayStation Portable . Released in January 2011 in Japan , it is the third game in the Valkyria series . Employing the same fusion of tactical and real @-@ time gameplay as its predecessors , the story runs parallel to the first game and follows the Nameless squad of the Gallian Militia and their fight against the Imperial invasion .

The game began development in 2010 , carrying over a large portion of the work done on Valkyria Chronicles II . While it retained the standard gameplay mechanics of the series , it featured new elements such as the BLiTZ system and modifications to the CP system . Upon release , the game sold about 102 @,@ 000 copies in its first week , reaching number 2 on the Japanese sales chart . Critics from gaming publications praised the story and strategic depth but noted that the game was short .

= = Gameplay = =

As with previous Valkyria Chronicles games , Valkyria Chronicles III is a tactical role @-@ playing game where players take control of a military unit and take part in missions against enemy forces . Stories are told through comic book @-@ like panels with voice acting , and individual characters can be given different classes and equipment to alter their abilities . The game systems from Valkyria Chronicles II were carried over and expanded upon : defeating enemies and completing various in @-@ mission tasks rewards players with experience points which can be used to level up characters and unlock new classes and weapon upgrades .

= = = Combat = = =

The game takes place on a 3D rendered map , with the player 's units represented on the map . Players select one of their units to control directly , allowing them to move across the map , take aim at enemies , and engage in combat . The game uses the BLiTZ targeting system , which allows players to take precise shots at enemy units . Upon engaging an enemy unit , players must select a body part to target : the head , body , or limbs . Different enemies have different weak points , and hitting them results in extra damage .

= Robert Boulter =

Robert Boulter is an English film , television and theatre actor . He had a guest @-@ starring role on the television series The Bill in 2000 . This was followed by a starring role in the play Herons written by Simon Stephens , which was performed at the Royal Court Theatre in 2001 . He had a guest @-@ starring role in the television series Murphy 's Law in 2003 . In 2004 he was cast in the play Burnt by the Sun . Between 2005 and 2008 he had recurring roles in the television series William and Mary and the BBC medical drama Casualty .

= = Career = =

Robert Boulter is an English film , television and theatre actor . He had a guest @-@ starring role on the television series The Bill in 2000 . This was followed by a starring role in the play Herons written by Simon Stephens , which was performed at the Royal Court Theatre in 2001 . He had a guest @-@ starring role in the television series Murphy 's Law in 2003 . In 2004 he was cast in the play Burnt by the Sun . Between 2005 and 2008 he had recurring roles in the television series William and Mary and the BBC medical drama Casualty .

= Tropical Storm Debby ( 1982 ) =

Tropical Storm Debby was a weak tropical storm in August 1982 that made landfall in Mexico . It was the fourth tropical cyclone and named storm of the 1982 Atlantic hurricane season . A tropical wave moved off the coast of Africa on August 4 and entered the southern Caribbean on August 12 . An area of disturbed weather formed over the southwestern Caribbean on August 13 and organized into a tropical depression by August 14 . The depression moved across Central America into the Pacific on August 15 and then weakened .

= = Meteorological history = =

The genesis of Tropical Storm Debby started with a tropical wave that moved off the coast of Africa on August 4 . The tropical wave entered the southern Caribbean on August 12 and developed into an area of disturbed weather over the southwestern Caribbean on August 13 . The disturbance moved over the Yucatan Peninsula on August 13 into the Bay of Campeche . A tropical depression formed over the Bay of Campeche by 1800 UTC on August 14 . The depression moved westward across the Bay and made landfall between Tampico and Tuxpan , Mexico early on August 15 .

= Machine learning =

Machine learning is a subset of artificial intelligence that provides systems the ability to automatically learn and improve from experience without being explicitly programmed . Machine learning focuses on the development of computer programs that can access data and use it to learn for themselves . The process of learning begins with observations or data , such as examples , direct experience , or instruction , in order to look for patterns in data and make better decisions in the future based on the examples that we provide .

= = Types of machine learning = =

Machine learning algorithms are often categorized as supervised or unsupervised . Supervised machine learning algorithms can apply what has been learned in the past to new data using labeled examples to predict future events . Starting from the analysis of a known training dataset , the learning algorithm produces an inferred function to make predictions about the output values . Unsupervised machine learning algorithms are used when the information used to train is neither classified nor labeled . Unsupervised learning studies how systems can infer a function to describe a hidden structure from unlabeled data .
"""


def _download_file(url: str, dest_path: Path) -> bool:
    """Download a single file. Returns True on success."""
    import ssl
    import shutil

    ssl_context = ssl.create_default_context()
    request = urllib.request.Request(
        url,
        headers={'User-Agent': 'Mozilla/5.0 (Windows NT 10.0; Win64; x64)'}
    )

    try:
        opener = urllib.request.build_opener(
            urllib.request.HTTPRedirectHandler(),
            urllib.request.HTTPSHandler(context=ssl_context)
        )
        with opener.open(request, timeout=60) as response:
            with open(dest_path, 'wb') as f:
                shutil.copyfileobj(response, f)
        return dest_path.exists() and dest_path.stat().st_size > 0
    except (OSError, urllib.error.URLError, TimeoutError) as e:
        print(f"    Download failed: {e}")
        return False


def _download_wikitext2_fallback(cache_dir: Optional[str] = None) -> dict:
    """
    Download WikiText-2 directly from source (fallback when datasets unavailable).

    Returns dict with 'train', 'validation', 'test' text.
    """
    if cache_dir is None:
        cache_dir = Path.home() / ".cache" / "wikitext2"
    else:
        cache_dir = Path(cache_dir)

    cache_dir.mkdir(parents=True, exist_ok=True)
    data_dir = cache_dir / "wikitext-2-raw"
    data_dir.mkdir(parents=True, exist_ok=True)

    result = {}
    files_map = {
        'train': 'wiki.train.raw',
        'validation': 'wiki.valid.raw',
        'test': 'wiki.test.raw'
    }

    for split, filename in files_map.items():
        filepath = data_dir / filename

        # Check if already cached
        if filepath.exists() and filepath.stat().st_size > 1000:
            with open(filepath, 'r', encoding='utf-8') as f:
                result[split] = f.read()
            continue

        # Try downloading from URLs
        print(f"  Downloading {split} split...")
        downloaded = False
        for url in WIKITEXT2_RAW_FILES.get(split, []):
            print(f"    Trying: {url[:50]}...")
            if _download_file(url, filepath):
                with open(filepath, 'r', encoding='utf-8') as f:
                    result[split] = f.read()
                downloaded = True
                print(f"    Success!")
                break

        # Ultimate fallback: use embedded sample
        if not downloaded:
            print(f"    Using embedded sample data for {split}")
            # Use the sample data, duplicated to make it larger
            sample = WIKITEXT2_SAMPLE * (50 if split == 'train' else 10)
            result[split] = sample
            with open(filepath, 'w', encoding='utf-8') as f:
                f.write(sample)

    print(f"WikiText-2 loaded from: {data_dir}")
    return result


def _download_wikitext103_fallback(cache_dir: Optional[str] = None) -> dict:
    """
    Download WikiText-103 directly from source (fallback when datasets unavailable).

    WikiText-103 is ~50x larger than WikiText-2 (~103M tokens vs ~2M tokens).

    Returns dict with 'train', 'validation', 'test' text.
    """
    if cache_dir is None:
        cache_dir = Path.home() / ".cache" / "wikitext103"
    else:
        cache_dir = Path(cache_dir)

    cache_dir.mkdir(parents=True, exist_ok=True)
    data_dir = cache_dir / "wikitext-103-raw"
    zip_path = cache_dir / "wikitext-103-raw-v1.zip"

    files_map = {
        'train': 'wiki.train.raw',
        'validation': 'wiki.valid.raw',
        'test': 'wiki.test.raw'
    }

    # Check if already extracted
    all_exist = all((data_dir / fname).exists() for fname in files_map.values())

    if not all_exist:
        # Download and extract
        if not zip_path.exists():
            print(f"  Downloading WikiText-103 (~180MB)...")
            downloaded = False
            for url in WIKITEXT103_URLS:
                print(f"    Trying: {url[:60]}...")
                if _download_file(url, zip_path):
                    print(f"    Download complete!")
                    downloaded = True
                    break
            if not downloaded:
                # Provide manual download instructions
                manual_path = cache_dir / "wikitext-103-raw-v1.zip"
                raise RuntimeError(
                    f"Failed to download WikiText-103 from all sources.\n\n"
                    f"MANUAL DOWNLOAD OPTION:\n"
                    f"1. Go to: https://huggingface.co/datasets/iohadrubin/wikitext-103-raw-v1/tree/main\n"
                    f"2. Download the parquet files OR fix your datasets installation:\n"
                    f"   pip uninstall pyarrow datasets\n"
                    f"   pip install pyarrow==15.0.0 datasets\n\n"
                    f"OR use WikiText-2 instead (smaller but works): --dataset wikitext-2"
                )

        # Extract
        print(f"  Extracting WikiText-103...")
        with zipfile.ZipFile(zip_path, 'r') as zf:
            zf.extractall(cache_dir)

        # The zip extracts to wikitext-103-raw-v1/, rename to wikitext-103-raw
        extracted_dir = cache_dir / "wikitext-103-raw-v1"
        if extracted_dir.exists() and not data_dir.exists():
            extracted_dir.rename(data_dir)

    # Read files
    result = {}
    for split, filename in files_map.items():
        filepath = data_dir / filename
        if filepath.exists():
            with open(filepath, 'r', encoding='utf-8') as f:
                result[split] = f.read()
        else:
            raise RuntimeError(f"WikiText-103 file not found: {filepath}")

    print(f"WikiText-103 loaded from: {data_dir}")
    return result


class WikiText2Dataset(Dataset):
    """
    WikiText-2 dataset for language modeling.

    Processes text into fixed-length sequences for autoregressive training:
        Input:  [tok_0, tok_1, ..., tok_{T-1}]
        Target: [tok_1, tok_2, ..., tok_T]

    Features:
        - Efficient tokenization using GPT-2 BPE tokenizer
        - Fixed sequence length with truncation/padding
        - Vocabulary size control (top K tokens)
        - Caches tokenized data for speed
    """

    def __init__(
        self,
        split: str = 'train',
        max_seq_len: int = 128,
        vocab_size: Optional[int] = None,
        tokenizer_name: str = 'gpt2',
        cache_dir: Optional[str] = None,
        vocab_mapping: Optional[Dict[int, int]] = None,
    ):
        """
        Initialize WikiText-2 dataset.

        Args:
            split: 'train', 'validation', or 'test'
            max_seq_len: Maximum sequence length (T)
            vocab_size: If provided, restrict to top K tokens
            tokenizer_name: HuggingFace tokenizer name
            cache_dir: Optional cache directory for dataset
            vocab_mapping: Pre-built vocabulary mapping (original_token -> new_id).
                          If provided, uses this mapping instead of building from
                          this split's frequencies. Essential for ensuring train/val
                          consistency when vocab restriction is used.
        """
        # Only transformers is required - datasets has fallback
        assert TRANSFORMERS_AVAILABLE, "transformers required for BPE tokenization! pip install transformers"

        self.split = split
        self.max_seq_len = max_seq_len
        self.vocab_size_limit = vocab_size

        # Load tokenizer
        self.tokenizer = AutoTokenizer.from_pretrained(tokenizer_name)

        # Add padding token if not present
        if self.tokenizer.pad_token is None:
            self.tokenizer.pad_token = self.tokenizer.eos_token

        self.pad_token_id = self.tokenizer.pad_token_id
        self.eos_token_id = self.tokenizer.eos_token_id

        # Load dataset (with fallback if datasets package unavailable)
        print(f"Loading WikiText-2 ({split}) for BPE tokenization...")

        if DATASETS_AVAILABLE:
            # Use HuggingFace datasets
            dataset = load_dataset('wikitext', 'wikitext-2-raw-v1', split=split, cache_dir=cache_dir)
            texts = [item['text'] for item in dataset if len(item['text'].strip()) > 0]
            full_text = '\n\n'.join(texts)
        else:
            # Fallback: download directly (same as character-level)
            print("  (Using direct download fallback - datasets package not available)")
            wikitext_data = _download_wikitext2_fallback(cache_dir)
            full_text = wikitext_data[split]

        # Clean up processed WikiText artifacts (fallback URL has processed version)
        import re
        unk_count = full_text.count('<unk>')
        if unk_count > 0:
            print(f"  Warning: Removing {unk_count} <unk> tokens from data (processed WikiText artifact)")
            # Replace <unk> with single space, preserve newlines
            full_text = re.sub(r'<unk>', '', full_text)
            # Only normalize multiple spaces (NOT newlines) - preserve paragraph structure!
            full_text = re.sub(r'[ \t]+', ' ', full_text)

        # Also fix @-@ (hyphen) and @,@ (comma) artifacts from processed WikiText
        full_text = full_text.replace(' @-@ ', '-')
        full_text = full_text.replace(' @,@ ', ',')
        full_text = full_text.replace(' @.@ ', '.')

        print(f"  Total characters: {len(full_text):,}")

        # Tokenize
        print(f"Tokenizing...")
        tokens = self.tokenizer.encode(full_text, add_special_tokens=False)

        # Restrict vocabulary if requested
        if vocab_size is not None and vocab_size < len(self.tokenizer):
            if vocab_mapping is not None:
                # Use provided mapping (ensures train/val consistency)
                print(f"  Using provided vocabulary mapping ({len(vocab_mapping)} tokens)...")
                tokens = self._apply_vocab_mapping(tokens, vocab_mapping)
            else:
                # Build mapping from this split's frequencies (only for train!)
                print(f"  Restricting vocabulary to {vocab_size} most frequent tokens...")
                tokens = self._restrict_vocab(tokens, vocab_size)

        self.tokens = torch.tensor(tokens, dtype=torch.long)

        print(f"  Tokenized: {len(self.tokens):,} tokens")
        print(f"  Vocabulary size: {self.get_vocab_size()}")

        # Calculate number of complete sequences
        # Each sequence is [tok_0...tok_T-1] → [tok_1...tok_T]
        self.num_sequences = max(1, len(self.tokens) - self.max_seq_len)

        print(f"  Number of sequences: {self.num_sequences:,}")

    def _restrict_vocab(self, tokens: List[int], target_vocab_size: int) -> List[int]:
        """
        Restrict tokens to top K most frequent.

        Tokens outside top K are replaced with <unk>.
        """
        # Count token frequencies
        token_counts = {}
        for tok in tokens:
            token_counts[tok] = token_counts.get(tok, 0) + 1

        # Reserve 1 slot for UNK, get top (K-1) tokens
        sorted_tokens = sorted(token_counts.items(), key=lambda x: x[1], reverse=True)

        # Get UNK token
        unk_token_id = self.tokenizer.unk_token_id
        if unk_token_id is None:
            # Use pad token as UNK if no UNK token
            unk_token_id = self.pad_token_id

        # Take top (K-1) tokens to leave room for UNK
        top_k_minus_1 = set([tok for tok, _ in sorted_tokens[:target_vocab_size - 1]])

        # Include UNK in vocabulary
        top_k_tokens = top_k_minus_1 | {unk_token_id}

        restricted_tokens = [
            tok if tok in top_k_tokens else unk_token_id
            for tok in tokens
        ]

        # Remap to contiguous vocabulary [0, 1, ..., K-1]
        # Sort but ensure UNK is last
        non_unk_tokens = sorted(top_k_minus_1)
        token_to_id = {tok: i for i, tok in enumerate(non_unk_tokens)}
        token_to_id[unk_token_id] = len(token_to_id)  # UNK is last (index K-1)

        self._vocab_mapping = token_to_id
        self._restricted_vocab_size = len(token_to_id)
        self._unk_id = token_to_id[unk_token_id]  # UNK is last (index K-1)

        return [token_to_id.get(tok, self._unk_id) for tok in restricted_tokens]

    def _apply_vocab_mapping(self, tokens: List[int], vocab_mapping: Dict[int, int]) -> List[int]:
        """
        Apply a pre-built vocabulary mapping to tokens.

        Used to ensure train/val consistency when vocab restriction is enabled.
        Tokens not in the mapping are mapped to UNK (highest ID in mapping).
        """
        self._vocab_mapping = vocab_mapping
        self._restricted_vocab_size = len(vocab_mapping)

        # UNK is the highest ID in the mapping
        self._unk_id = max(vocab_mapping.values())

        return [vocab_mapping.get(tok, self._unk_id) for tok in tokens]

    def get_vocab_mapping(self) -> Optional[Dict[int, int]]:
        """Return the vocabulary mapping if vocab restriction was applied."""
        return getattr(self, '_vocab_mapping', None)

    def get_vocab_size(self) -> int:
        """Return effective vocabulary size."""
        if hasattr(self, '_restricted_vocab_size'):
            return self._restricted_vocab_size
        return len(self.tokenizer)

    def encode(self, text: str) -> List[int]:
        """Encode text to token IDs (handles vocab restriction)."""
        tokens = self.tokenizer.encode(text, add_special_tokens=False)
        if hasattr(self, '_vocab_mapping'):
            tokens = [self._vocab_mapping.get(tok, self._unk_id) for tok in tokens]
        return tokens

    def decode(self, ids) -> str:
        """Decode token IDs back to text (handles vocab restriction)."""
        if isinstance(ids, torch.Tensor):
            ids = ids.tolist()
        if hasattr(self, '_vocab_mapping'):
            # Build inverse mapping: new_id -> original_token_id
            if not hasattr(self, '_inverse_vocab_mapping'):
                self._inverse_vocab_mapping = {v: k for k, v in self._vocab_mapping.items()}
            # Map back to original tokens, skip UNK tokens
            original_tokens = []
            for tok_id in ids:
                if tok_id in self._inverse_vocab_mapping:
                    original_tokens.append(self._inverse_vocab_mapping[tok_id])
            return self.tokenizer.decode(original_tokens)
        else:
            return self.tokenizer.decode(ids)

    def __len__(self) -> int:
        """Number of sequences in dataset."""
        return self.num_sequences

    def __getitem__(self, idx: int) -> Tuple[torch.Tensor, torch.Tensor]:
        """
        Get a single training example.

        Args:
            idx: Sequence index

        Returns:
            input_ids: (max_seq_len,) token IDs
            target_ids: (max_seq_len,) next-token targets
        """
        # Extract sequence starting at idx
        start_idx = idx
        end_idx = start_idx + self.max_seq_len

        # Input: tokens[start:end]
        # Target: tokens[start+1:end+1]
        input_ids = self.tokens[start_idx:end_idx]
        target_ids = self.tokens[start_idx + 1:end_idx + 1]

        # Pad if necessary (should only happen at end of dataset)
        if len(input_ids) < self.max_seq_len:
            padding_length = self.max_seq_len - len(input_ids)
            input_ids = torch.cat([
                input_ids,
                torch.full((padding_length,), self.pad_token_id, dtype=torch.long)
            ])
            target_ids = torch.cat([
                target_ids,
                torch.full((padding_length,), self.pad_token_id, dtype=torch.long)
            ])

        return input_ids, target_ids


class WikiText2TiktokenDataset(Dataset):
    """
    WikiText dataset using tiktoken (OpenAI's fast BPE tokenizer).

    Supports WikiText-2 (~2M tokens) and WikiText-103 (~103M tokens).
    Lighter weight than transformers - no sklearn/pyarrow dependencies.
    Uses GPT-2's tokenizer by default (50257 vocab).
    """

    def __init__(
        self,
        split: str = 'train',
        max_seq_len: int = 128,
        vocab_size: Optional[int] = None,
        cache_dir: Optional[str] = None,
        vocab_mapping: Optional[Dict[int, int]] = None,
        dataset: str = 'wikitext-2',
    ):
        """
        Initialize WikiText dataset with tiktoken.

        Args:
            split: 'train', 'validation', or 'test'
            max_seq_len: Maximum sequence length (T)
            vocab_size: If provided, restrict to top K tokens
            cache_dir: Optional cache directory for dataset
            vocab_mapping: Pre-built vocabulary mapping (original_token -> new_id).
                          If provided, uses this mapping instead of building from
                          this split's frequencies. Essential for ensuring train/val
                          consistency when vocab restriction is used.
            dataset: 'wikitext-2' (~2M tokens) or 'wikitext-103' (~103M tokens)
        """
        assert TIKTOKEN_AVAILABLE, "tiktoken required! pip install tiktoken"
        assert dataset in DATASET_CONFIGS, f"Unknown dataset: {dataset}. Use 'wikitext-2' or 'wikitext-103'"

        self.split = split
        self.max_seq_len = max_seq_len
        self.vocab_size_limit = vocab_size
        self.dataset_name = dataset

        # Load GPT-2 tokenizer via tiktoken
        self.tokenizer = tiktoken.get_encoding("gpt2")
        self._full_vocab_size = self.tokenizer.n_vocab  # 50257

        # Tiktoken doesn't have explicit pad/eos, use token 0 as pad
        self.pad_token_id = 0
        self.eos_token_id = 50256  # GPT-2's <|endoftext|>

        # Load dataset
        hf_config = DATASET_CONFIGS[dataset]
        print(f"Loading {dataset.upper()} ({split}) for BPE tokenization (tiktoken)...")
        print(f"  DATASETS_AVAILABLE={DATASETS_AVAILABLE}")

        if DATASETS_AVAILABLE:
            dataset_obj = load_dataset('wikitext', hf_config, split=split, cache_dir=cache_dir)
            texts = [item['text'] for item in dataset_obj if len(item['text'].strip()) > 0]
            full_text = '\n\n'.join(texts)
        else:
            print("  (Using direct download fallback)")
            if dataset == 'wikitext-103':
                wikitext_data = _download_wikitext103_fallback(cache_dir)
            else:
                wikitext_data = _download_wikitext2_fallback(cache_dir)
            full_text = wikitext_data[split]

        # Clean up processed WikiText artifacts (fallback URL has processed version)
        import re
        unk_count = full_text.count('<unk>')
        if unk_count > 0:
            print(f"  Warning: Removing {unk_count} <unk> tokens from data (processed WikiText artifact)")
            # Replace <unk> with single space, preserve newlines
            full_text = re.sub(r'<unk>', '', full_text)
            # Only normalize multiple spaces (NOT newlines) - preserve paragraph structure!
            full_text = re.sub(r'[ \t]+', ' ', full_text)

        # Also fix @-@ (hyphen) and @,@ (comma) artifacts from processed WikiText
        full_text = full_text.replace(' @-@ ', '-')
        full_text = full_text.replace(' @,@ ', ',')
        full_text = full_text.replace(' @.@ ', '.')

        print(f"  Total characters: {len(full_text):,}")

        # Tokenize
        print(f"Tokenizing with tiktoken (GPT-2 BPE)...")
        tokens = self.tokenizer.encode(full_text)

        # Restrict vocabulary if requested
        if vocab_size is not None and vocab_size < self._full_vocab_size:
            if vocab_mapping is not None:
                # Use provided mapping (ensures train/val consistency)
                print(f"  Using provided vocabulary mapping ({len(vocab_mapping)} tokens)...")
                tokens = self._apply_vocab_mapping(tokens, vocab_mapping)
            else:
                # Build mapping from this split's frequencies (only for train!)
                print(f"  Restricting vocabulary to {vocab_size} most frequent tokens...")
                tokens = self._restrict_vocab(tokens, vocab_size)

        self.tokens = torch.tensor(tokens, dtype=torch.long)

        print(f"  Tokenized: {len(self.tokens):,} tokens")
        print(f"  Vocabulary size: {self.get_vocab_size()}")

        self.num_sequences = max(1, len(self.tokens) - self.max_seq_len)
        print(f"  Number of sequences: {self.num_sequences:,}")

    def _restrict_vocab(self, tokens: List[int], target_vocab_size: int) -> List[int]:
        """Restrict tokens to top K most frequent."""
        # Count frequencies
        token_counts = {}
        for tok in tokens:
            token_counts[tok] = token_counts.get(tok, 0) + 1

        sorted_tokens = sorted(token_counts.items(), key=lambda x: x[1], reverse=True)

        # Use last slot for UNK
        unk_id = target_vocab_size - 1
        top_k_minus_1 = set([tok for tok, _ in sorted_tokens[:target_vocab_size - 1]])

        # Build mapping: original_token_id -> new_contiguous_id
        non_unk_tokens = sorted(top_k_minus_1)
        token_to_id = {tok: i for i, tok in enumerate(non_unk_tokens)}
        # Note: UNK is implicit - any token not in mapping maps to unk_id

        self._vocab_mapping = token_to_id
        self._restricted_vocab_size = target_vocab_size
        self._unk_id = unk_id

        return [token_to_id.get(tok, unk_id) for tok in tokens]

    def _apply_vocab_mapping(self, tokens: List[int], vocab_mapping: Dict[int, int]) -> List[int]:
        """
        Apply a pre-built vocabulary mapping to tokens.

        Used to ensure train/val consistency when vocab restriction is enabled.
        Tokens not in the mapping are mapped to UNK (highest ID in mapping).
        """
        self._vocab_mapping = vocab_mapping
        self._restricted_vocab_size = len(vocab_mapping) + 1  # +1 for UNK
        self._unk_id = len(vocab_mapping)  # UNK is the last ID

        return [vocab_mapping.get(tok, self._unk_id) for tok in tokens]

    def get_vocab_mapping(self) -> Optional[Dict[int, int]]:
        """Return the vocabulary mapping if vocab restriction was applied."""
        return getattr(self, '_vocab_mapping', None)

    def encode(self, text: str) -> List[int]:
        """Encode text to token IDs (handles vocab restriction)."""
        tokens = self.tokenizer.encode(text)
        if hasattr(self, '_vocab_mapping'):
            tokens = [self._vocab_mapping.get(tok, self._unk_id) for tok in tokens]
        return tokens

    def decode(self, ids) -> str:
        """Decode token IDs back to text (handles vocab restriction)."""
        if isinstance(ids, torch.Tensor):
            ids = ids.tolist()
        if hasattr(self, '_vocab_mapping'):
            # Build inverse mapping: new_id -> original_token_id
            if not hasattr(self, '_inverse_vocab_mapping'):
                self._inverse_vocab_mapping = {v: k for k, v in self._vocab_mapping.items()}
            # Map back to original tokens, skip UNK tokens
            original_tokens = []
            for tok_id in ids:
                if tok_id in self._inverse_vocab_mapping:
                    original_tokens.append(self._inverse_vocab_mapping[tok_id])
                # Skip UNK tokens in output
            return self.tokenizer.decode(original_tokens)
        else:
            return self.tokenizer.decode(ids)

    def get_vocab_size(self) -> int:
        if hasattr(self, '_restricted_vocab_size'):
            return self._restricted_vocab_size
        return self._full_vocab_size

    def __len__(self) -> int:
        return self.num_sequences

    def __getitem__(self, idx: int) -> Tuple[torch.Tensor, torch.Tensor]:
        start_idx = idx
        end_idx = start_idx + self.max_seq_len

        input_ids = self.tokens[start_idx:end_idx]
        target_ids = self.tokens[start_idx + 1:end_idx + 1]

        if len(input_ids) < self.max_seq_len:
            padding_length = self.max_seq_len - len(input_ids)
            input_ids = torch.cat([
                input_ids,
                torch.full((padding_length,), self.pad_token_id, dtype=torch.long)
            ])
            target_ids = torch.cat([
                target_ids,
                torch.full((padding_length,), self.pad_token_id, dtype=torch.long)
            ])

        return input_ids, target_ids


class WikiText2CharDataset(Dataset):
    """
    Character-level WikiText-2 dataset for language modeling.

    Processes text at character level with fixed-length sequences.
    Perfect for minimal proof-of-principle experiments.

    Features:
        - Character-level modeling (vocab_size ≤ 256 for ASCII/extended ASCII)
        - Fixed sequence length
        - Direct character-to-index mapping
        - No tokenizer required
    """

    def __init__(
        self,
        split: str = 'train',
        max_seq_len: int = 32,
        vocab_size: int = 256,
        cache_dir: Optional[str] = None,
        vocab_mapping: Optional[Dict[str, int]] = None,
    ):
        """
        Initialize character-level WikiText-2 dataset.

        Args:
            split: 'train', 'validation', or 'test'
            max_seq_len: Maximum sequence length (N)
            vocab_size: Maximum vocabulary size (default 256 for extended ASCII)
            cache_dir: Optional cache directory for dataset
            vocab_mapping: Pre-built character-to-id mapping (from train split).
                          If provided, uses this mapping instead of building from
                          this split's frequencies. Essential for ensuring train/val
                          consistency.
        """
        self.split = split
        self.max_seq_len = max_seq_len
        self.vocab_size = vocab_size

        # Load dataset (with fallback if datasets package unavailable)
        print(f"Loading WikiText-2 ({split}) for character-level modeling...")

        if DATASETS_AVAILABLE:
            # Use HuggingFace datasets
            dataset = load_dataset('wikitext', 'wikitext-2-raw-v1', split=split, cache_dir=cache_dir)
            texts = [item['text'] for item in dataset if len(item['text'].strip()) > 0]
            full_text = '\n\n'.join(texts)
        else:
            # Fallback: download directly
            print("  (Using direct download fallback - datasets package not available)")
            wikitext_data = _download_wikitext2_fallback(cache_dir)
            full_text = wikitext_data[split]

        # Clean up processed WikiText artifacts (fallback URL has processed version)
        import re
        unk_count = full_text.count('<unk>')
        if unk_count > 0:
            print(f"  Warning: Removing {unk_count} <unk> tokens from data (processed WikiText artifact)")
            # Replace <unk> with single space, preserve newlines
            full_text = re.sub(r'<unk>', '', full_text)
            # Only normalize multiple spaces (NOT newlines) - preserve paragraph structure!
            full_text = re.sub(r'[ \t]+', ' ', full_text)

        # Also fix @-@ (hyphen) and @,@ (comma) artifacts from processed WikiText
        full_text = full_text.replace(' @-@ ', '-')
        full_text = full_text.replace(' @,@ ', ',')
        full_text = full_text.replace(' @.@ ', '.')

        print(f"  Total characters: {len(full_text):,}")

        # Build or use provided character vocabulary
        self.pad_token_id = 0
        self.unk_token_id = 1

        if vocab_mapping is not None:
            # Use provided mapping (ensures train/val consistency)
            print(f"  Using provided vocabulary mapping ({len(vocab_mapping)} chars)...")
            self.char_to_id = vocab_mapping.copy()
        else:
            # Build vocabulary from this split's frequencies (only for train!)
            print(f"  Building vocabulary from {split} frequencies...")
            # Count character frequencies
            char_counts = {}
            for char in full_text:
                char_counts[char] = char_counts.get(char, 0) + 1

            # Sort by frequency
            sorted_chars = sorted(char_counts.items(), key=lambda x: x[1], reverse=True)

            # Take top vocab_size - 2 (reserve for PAD and UNK)
            top_chars = [char for char, _ in sorted_chars[:vocab_size - 2]]

            # Build vocabulary: PAD=0, UNK=1, then top characters
            self.char_to_id = {'<PAD>': 0, '<UNK>': 1}
            for i, char in enumerate(top_chars):
                self.char_to_id[char] = i + 2

        # Create reverse mapping for decoding
        self.id_to_char = {v: k for k, v in self.char_to_id.items()}

        # Convert text to indices
        char_indices = []
        for char in full_text:
            if char in self.char_to_id:
                char_indices.append(self.char_to_id[char])
            else:
                char_indices.append(self.unk_token_id)

        self.tokens = torch.tensor(char_indices, dtype=torch.long)

        # Calculate number of complete sequences
        self.num_sequences = max(1, len(self.tokens) - self.max_seq_len)

        print(f"  Character vocab size: {len(self.char_to_id)}")
        print(f"  Number of sequences: {self.num_sequences:,}")
        print(f"  Total chars: {len(self.tokens):,}")

    def get_vocab_size(self) -> int:
        """Return actual vocabulary size."""
        return len(self.char_to_id)

    def get_vocab_mapping(self) -> Dict[str, int]:
        """Return the character-to-id vocabulary mapping."""
        return self.char_to_id.copy()

    def encode(self, text: str) -> List[int]:
        """Encode text to character IDs."""
        return [self.char_to_id.get(c, self.unk_token_id) for c in text]

    def decode(self, indices) -> str:
        """Decode indices back to text."""
        if isinstance(indices, torch.Tensor):
            indices = indices.tolist()
        chars = []
        for idx in indices:
            chars.append(self.id_to_char.get(idx, '<UNK>'))
        return ''.join(chars)

    def __len__(self) -> int:
        """Number of sequences in dataset."""
        return self.num_sequences

    def __getitem__(self, idx: int) -> Tuple[torch.Tensor, torch.Tensor]:
        """
        Get a single training example.

        Args:
            idx: Sequence index

        Returns:
            input_ids: (max_seq_len,) character IDs
            target_ids: (max_seq_len,) next-character targets
        """
        # Extract sequence starting at idx
        start_idx = idx
        end_idx = start_idx + self.max_seq_len

        # Input: chars[start:end]
        # Target: chars[start+1:end+1]
        input_ids = self.tokens[start_idx:end_idx]
        target_ids = self.tokens[start_idx + 1:end_idx + 1]

        # Pad if necessary
        if len(input_ids) < self.max_seq_len:
            padding_length = self.max_seq_len - len(input_ids)
            input_ids = torch.cat([
                input_ids,
                torch.full((padding_length,), self.pad_token_id, dtype=torch.long)
            ])
            target_ids = torch.cat([
                target_ids,
                torch.full((padding_length,), self.pad_token_id, dtype=torch.long)
            ])

        return input_ids, target_ids


class WikiText2ByteDataset(Dataset):
    """
    Byte-level WikiText-2 dataset for language modeling.

    Encodes text as raw bytes (0-255), giving a fixed vocabulary of 256.
    No external tokenizer required - pure Python!

    Features:
        - Byte-level modeling (vocab_size = 256, always)
        - Fixed sequence length
        - No external dependencies
        - Can restrict to top K bytes if desired
    """

    def __init__(
        self,
        split: str = 'train',
        max_seq_len: int = 32,
        vocab_size: int = 256,
        cache_dir: Optional[str] = None,
        vocab_mapping: Optional[Dict[int, int]] = None,
    ):
        """
        Initialize byte-level WikiText-2 dataset.

        Args:
            split: 'train', 'validation', or 'test'
            max_seq_len: Maximum sequence length (N)
            vocab_size: Maximum vocabulary size (up to 256)
            cache_dir: Optional cache directory for dataset
            vocab_mapping: Pre-built byte-to-id mapping (from train split).
                          If provided, uses this mapping instead of building from
                          this split's frequencies. Essential for ensuring train/val
                          consistency when vocab restriction is used.
        """
        self.split = split
        self.max_seq_len = max_seq_len
        self.vocab_size = min(vocab_size, 256)  # Cap at 256 bytes

        # Load dataset with fallback
        print(f"Loading WikiText-2 ({split}) for byte-level modeling...")

        if DATASETS_AVAILABLE:
            dataset = load_dataset('wikitext', 'wikitext-2-raw-v1', split=split, cache_dir=cache_dir)
            texts = [item['text'] for item in dataset if len(item['text'].strip()) > 0]
            full_text = '\n\n'.join(texts)
        else:
            print("  (Using direct download fallback)")
            wikitext_data = _download_wikitext2_fallback(cache_dir)
            full_text = wikitext_data[split]

        print(f"  Total characters: {len(full_text):,}")

        # Encode as bytes
        text_bytes = full_text.encode('utf-8', errors='replace')

        # PAD = 0, so shift all bytes by 1, and use 0 for padding
        # Vocab: 0=PAD, 1-256=bytes (so actual byte value + 1)
        self.pad_token_id = 0

        # If restricting vocab, find most frequent bytes and remap
        if self.vocab_size < 256:
            if vocab_mapping is not None:
                # Use provided mapping (ensures train/val consistency)
                print(f"  Using provided vocabulary mapping ({len(vocab_mapping)} bytes)...")
                self.byte_to_id = vocab_mapping.copy()
                self.unk_id = self.vocab_size  # Last position for unknown
                self._actual_vocab_size = self.vocab_size + 1  # +1 for UNK token
            else:
                # Build mapping from this split's frequencies (only for train!)
                print(f"  Building vocabulary from {split} frequencies...")
                # Count byte frequencies
                byte_counts = {}
                for b in text_bytes:
                    byte_counts[b] = byte_counts.get(b, 0) + 1

                # Get top (vocab_size - 1) bytes (reserve 0 for PAD)
                sorted_bytes = sorted(byte_counts.items(), key=lambda x: x[1], reverse=True)
                top_bytes = [b for b, _ in sorted_bytes[:self.vocab_size - 1]]

                # Build mapping: byte -> token_id (1 to vocab_size-1), unknown -> vocab_size-1
                self.byte_to_id = {b: i + 1 for i, b in enumerate(top_bytes)}
                self.unk_id = self.vocab_size  # Last position for unknown
                self._actual_vocab_size = self.vocab_size + 1  # +1 for UNK token

            # Convert bytes to token IDs
            byte_indices = []
            for b in text_bytes:
                if b in self.byte_to_id:
                    byte_indices.append(self.byte_to_id[b])
                else:
                    byte_indices.append(self.unk_id)
        else:
            # Full 256 bytes: token_id = byte_value + 1 (0 reserved for PAD)
            self._actual_vocab_size = 257  # 0=PAD, 1-256=bytes
            self.byte_to_id = None  # No mapping needed for full vocab
            byte_indices = [b + 1 for b in text_bytes]

        self.tokens = torch.tensor(byte_indices, dtype=torch.long)

        # Calculate number of complete sequences
        self.num_sequences = max(1, len(self.tokens) - self.max_seq_len)

        print(f"  Byte vocab size: {self._actual_vocab_size}")
        print(f"  Number of sequences: {self.num_sequences:,}")
        print(f"  Total bytes: {len(self.tokens):,}")

    def get_vocab_size(self) -> int:
        """Return actual vocabulary size."""
        return self._actual_vocab_size

    def get_vocab_mapping(self) -> Optional[Dict[int, int]]:
        """Return the byte-to-id vocabulary mapping if vocab restriction was applied."""
        if self.byte_to_id is not None:
            return self.byte_to_id.copy()
        return None

    def __len__(self) -> int:
        return self.num_sequences

    def __getitem__(self, idx: int) -> Tuple[torch.Tensor, torch.Tensor]:
        start_idx = idx
        end_idx = start_idx + self.max_seq_len

        input_ids = self.tokens[start_idx:end_idx]
        target_ids = self.tokens[start_idx + 1:end_idx + 1]

        # Pad if necessary
        if len(input_ids) < self.max_seq_len:
            padding_length = self.max_seq_len - len(input_ids)
            input_ids = torch.cat([
                input_ids,
                torch.full((padding_length,), self.pad_token_id, dtype=torch.long)
            ])
            target_ids = torch.cat([
                target_ids,
                torch.full((padding_length,), self.pad_token_id, dtype=torch.long)
            ])

        return input_ids, target_ids


def create_byte_dataloaders(
    max_seq_len: int = 32,
    batch_size: int = 16,
    vocab_size: int = 256,
    num_workers: int = 0,
    cache_dir: Optional[str] = None,
) -> Tuple[DataLoader, DataLoader, int]:
    """
    Create byte-level dataloaders. NO EXTERNAL PACKAGES REQUIRED!

    This is the simplest option that gives you a configurable vocab size
    without needing transformers or datasets packages.

    Args:
        max_seq_len: Maximum sequence length
        batch_size: Batch size
        vocab_size: Max vocab size (up to 256 for full byte range)
        num_workers: Number of data loading workers
        cache_dir: Optional cache directory

    Returns:
        train_loader, val_loader, actual_vocab_size
    """
    print("="*70)
    print("CREATING BYTE-LEVEL WIKITEXT-2 DATALOADERS")
    print("="*70)
    print("(No external tokenizer required - pure byte encoding)")

    train_dataset = WikiText2ByteDataset(
        split='train',
        max_seq_len=max_seq_len,
        vocab_size=vocab_size,
        cache_dir=cache_dir,
    )

    # Get vocab mapping from train to ensure consistency
    # (only relevant when vocab_size < 256)
    train_vocab_mapping = train_dataset.get_vocab_mapping()

    val_dataset = WikiText2ByteDataset(
        split='validation',
        max_seq_len=max_seq_len,
        vocab_size=vocab_size,
        cache_dir=cache_dir,
        vocab_mapping=train_vocab_mapping,  # Use train's mapping!
    )

    actual_vocab_size = train_dataset.get_vocab_size()

    train_loader = DataLoader(
        train_dataset,
        batch_size=batch_size,
        shuffle=True,
        num_workers=num_workers,
        pin_memory=True if torch.cuda.is_available() else False,
        drop_last=True,
        worker_init_fn=_worker_init_fn,  # Reproducibility: seed workers
    )

    val_loader = DataLoader(
        val_dataset,
        batch_size=batch_size,
        shuffle=False,
        num_workers=num_workers,
        pin_memory=True if torch.cuda.is_available() else False,
        drop_last=False,
        worker_init_fn=_worker_init_fn,  # Reproducibility: seed workers
    )

    print(f"\n{'='*70}")
    print(f"DATALOADERS CREATED")
    print(f"{'='*70}")
    print(f"Train batches: {len(train_loader):,}")
    print(f"Val batches:   {len(val_loader):,}")
    print(f"Vocabulary:    {actual_vocab_size} bytes")
    print(f"{'='*70}\n")

    return train_loader, val_loader, actual_vocab_size


def create_char_dataloaders(
    max_seq_len: int = 32,
    batch_size: int = 16,
    vocab_size: int = 256,
    num_workers: int = 0,
    cache_dir: Optional[str] = None,
    include_test: bool = False,
) -> Tuple[DataLoader, DataLoader, int] | Tuple[DataLoader, DataLoader, DataLoader, int]:
    """
    Create train, validation, and optionally test dataloaders for character-level WikiText-2.

    Args:
        max_seq_len: Maximum sequence length (default 32 for publication)
        batch_size: Batch size (default 16)
        vocab_size: Maximum vocabulary size (default 256 for extended ASCII)
        num_workers: Number of data loading workers
        cache_dir: Optional cache directory
        include_test: If True, also return test dataloader

    Returns:
        If include_test=False (default):
            train_loader: Training dataloader
            val_loader: Validation dataloader
            vocab_size: Actual vocabulary size
        If include_test=True:
            train_loader: Training dataloader
            val_loader: Validation dataloader
            test_loader: Test dataloader
            vocab_size: Actual vocabulary size

    Example:
        >>> train_loader, val_loader, vocab_size = create_char_dataloaders(
        ...     max_seq_len=32,
        ...     batch_size=16,
        ...     vocab_size=256,
        ... )
        >>> # Or with test set:
        >>> train_loader, val_loader, test_loader, vocab_size = create_char_dataloaders(
        ...     max_seq_len=32,
        ...     batch_size=16,
        ...     include_test=True,
        ... )
    """
    # Note: No longer requires datasets package - has fallback download!

    print("="*70)
    print("CREATING CHARACTER-LEVEL WIKITEXT-2 DATALOADERS")
    print("="*70)
    if not DATASETS_AVAILABLE:
        print("(Using direct download fallback - datasets package not available)")

    # Create datasets
    # IMPORTANT: Train dataset builds vocab mapping, val dataset reuses it
    # This ensures consistent char->id mapping across splits
    train_dataset = WikiText2CharDataset(
        split='train',
        max_seq_len=max_seq_len,
        vocab_size=vocab_size,
        cache_dir=cache_dir,
    )

    # Get vocab mapping from train to ensure consistency
    train_vocab_mapping = train_dataset.get_vocab_mapping()

    val_dataset = WikiText2CharDataset(
        split='validation',
        max_seq_len=max_seq_len,
        vocab_size=vocab_size,
        cache_dir=cache_dir,
        vocab_mapping=train_vocab_mapping,  # Use train's mapping!
    )

    # Get actual vocabulary size
    actual_vocab_size = train_dataset.get_vocab_size()

    # Create dataloaders
    train_loader = DataLoader(
        train_dataset,
        batch_size=batch_size,
        shuffle=True,
        num_workers=num_workers,
        pin_memory=True if torch.cuda.is_available() else False,
        drop_last=True,
        worker_init_fn=_worker_init_fn,  # Reproducibility: seed workers
    )

    val_loader = DataLoader(
        val_dataset,
        batch_size=batch_size,
        shuffle=False,
        num_workers=num_workers,
        pin_memory=True if torch.cuda.is_available() else False,
        drop_last=False,
        worker_init_fn=_worker_init_fn,  # Reproducibility: seed workers
    )

    # Create test loader if requested
    test_loader = None
    if include_test:
        test_dataset = WikiText2CharDataset(
            split='test',
            max_seq_len=max_seq_len,
            vocab_size=vocab_size,
            cache_dir=cache_dir,
            vocab_mapping=train_vocab_mapping,  # Use train's mapping!
        )
        test_loader = DataLoader(
            test_dataset,
            batch_size=batch_size,
            shuffle=False,
            num_workers=num_workers,
            pin_memory=True if torch.cuda.is_available() else False,
            drop_last=False,
            worker_init_fn=_worker_init_fn,  # Reproducibility: seed workers
        )

    print(f"\n{'='*70}")
    print(f"DATALOADERS CREATED")
    print(f"{'='*70}")
    print(f"Train batches: {len(train_loader):,}")
    print(f"Val batches:   {len(val_loader):,}")
    if include_test:
        print(f"Test batches:  {len(test_loader):,}")
    print(f"Vocabulary:    {actual_vocab_size} characters")
    print(f"Batch size:    {batch_size}")
    print(f"Sequence len:  {max_seq_len}")
    print(f"{'='*70}\n")

    if include_test:
        return train_loader, val_loader, test_loader, actual_vocab_size
    return train_loader, val_loader, actual_vocab_size


def create_dataloaders(
    max_seq_len: int = 128,
    batch_size: int = 8,
    vocab_size: Optional[int] = None,
    num_workers: int = 0,
    cache_dir: Optional[str] = None,
    tokenizer_name: str = 'gpt2',
    dataset: str = 'wikitext-103',
    include_test: bool = False,
    return_tokenizer: bool = False,
) -> Tuple[DataLoader, DataLoader, int] | Tuple[DataLoader, DataLoader, DataLoader, int]:
    """
    Create train, validation, and optionally test dataloaders for WikiText.

    Uses tiktoken (OpenAI's fast tokenizer) if available, falls back to
    transformers if not. Tiktoken is preferred as it has no heavy dependencies.

    Args:
        max_seq_len: Maximum sequence length
        batch_size: Batch size
        vocab_size: If provided, restrict vocabulary to top K tokens
        num_workers: Number of data loading workers
        cache_dir: Optional cache directory
        tokenizer_name: HuggingFace tokenizer name (only used if tiktoken unavailable)
        dataset: 'wikitext-2' (~2M tokens) or 'wikitext-103' (~103M tokens, default)
        include_test: If True, also return test dataloader
        return_tokenizer: If True, also return the train dataset (has .decode() method)

    Returns:
        If include_test=False, return_tokenizer=False (default):
            train_loader, val_loader, vocab_size
        If include_test=True, return_tokenizer=False:
            train_loader, val_loader, test_loader, vocab_size
        If include_test=False, return_tokenizer=True:
            train_loader, val_loader, vocab_size, tokenizer
        If include_test=True, return_tokenizer=True:
            train_loader, val_loader, test_loader, vocab_size, tokenizer

        The tokenizer is actually the train_dataset which has .decode() and .encode() methods.

    Example:
        >>> train_loader, val_loader, vocab_size = create_dataloaders(
        ...     max_seq_len=128,
        ...     batch_size=8,
        ...     vocab_size=5000,
        ...     dataset='wikitext-103',  # Use larger dataset
        ... )
        >>> # Or with test set:
        >>> train_loader, val_loader, test_loader, vocab_size = create_dataloaders(
        ...     max_seq_len=128,
        ...     batch_size=8,
        ...     include_test=True,
        ... )
        >>> for batch_idx, (input_ids, target_ids) in enumerate(train_loader):
        ...     # input_ids: (B, T), target_ids: (B, T)
        ...     logits = model(input_ids)
        ...     loss = criterion(logits, target_ids)
    """
    # Prefer tiktoken (lightweight), fall back to transformers
    if not BPE_AVAILABLE:
        raise ImportError(
            "BPE tokenization requires tiktoken or transformers!\n"
            "  pip install tiktoken  (recommended - lightweight)\n"
            "  pip install transformers  (alternative - heavier)"
        )

    dataset_upper = dataset.upper()
    print("="*70)
    if TIKTOKEN_AVAILABLE:
        print(f"CREATING {dataset_upper} DATALOADERS (BPE via tiktoken)")
    else:
        print(f"CREATING {dataset_upper} DATALOADERS (BPE via transformers)")
    print("="*70)
    if not DATASETS_AVAILABLE:
        print("(Using direct download fallback - datasets package not available)")

    # Create datasets - prefer tiktoken
    # IMPORTANT: Train dataset builds vocab mapping, val dataset reuses it
    # This ensures consistent token->id mapping across splits
    if TIKTOKEN_AVAILABLE:
        train_dataset = WikiText2TiktokenDataset(
            split='train',
            max_seq_len=max_seq_len,
            vocab_size=vocab_size,
            cache_dir=cache_dir,
            dataset=dataset,
        )

        # Get vocab mapping from train to ensure consistency
        train_vocab_mapping = train_dataset.get_vocab_mapping()

        val_dataset = WikiText2TiktokenDataset(
            split='validation',
            max_seq_len=max_seq_len,
            vocab_size=vocab_size,
            cache_dir=cache_dir,
            vocab_mapping=train_vocab_mapping,  # Use train's mapping!
            dataset=dataset,
        )
    else:
        train_dataset = WikiText2Dataset(
            split='train',
            max_seq_len=max_seq_len,
            vocab_size=vocab_size,
            tokenizer_name=tokenizer_name,
            cache_dir=cache_dir,
        )

        # Get vocab mapping from train to ensure consistency
        train_vocab_mapping = train_dataset.get_vocab_mapping()

        val_dataset = WikiText2Dataset(
            split='validation',
            max_seq_len=max_seq_len,
            vocab_size=vocab_size,
            tokenizer_name=tokenizer_name,
            cache_dir=cache_dir,
            vocab_mapping=train_vocab_mapping,  # Use train's mapping!
        )

    # Get actual vocabulary size (may differ from requested if restricted)
    actual_vocab_size = train_dataset.get_vocab_size()

    # Create dataloaders
    train_loader = DataLoader(
        train_dataset,
        batch_size=batch_size,
        shuffle=True,
        num_workers=num_workers,
        pin_memory=True if torch.cuda.is_available() else False,
        drop_last=True,  # Drop incomplete batches for consistent shapes
        worker_init_fn=_worker_init_fn,  # Reproducibility: seed workers
    )

    val_loader = DataLoader(
        val_dataset,
        batch_size=batch_size,
        shuffle=False,
        num_workers=num_workers,
        pin_memory=True if torch.cuda.is_available() else False,
        drop_last=False,
        worker_init_fn=_worker_init_fn,  # Reproducibility: seed workers
    )

    # Create test dataloader if requested
    test_loader = None
    if include_test:
        if TIKTOKEN_AVAILABLE:
            test_dataset = WikiText2TiktokenDataset(
                split='test',
                max_seq_len=max_seq_len,
                vocab_size=vocab_size,
                cache_dir=cache_dir,
                vocab_mapping=train_vocab_mapping,  # Use train's mapping!
                dataset=dataset,
            )
        else:
            test_dataset = WikiText2Dataset(
                split='test',
                max_seq_len=max_seq_len,
                vocab_size=vocab_size,
                tokenizer_name=tokenizer_name,
                cache_dir=cache_dir,
                vocab_mapping=train_vocab_mapping,  # Use train's mapping!
            )

        test_loader = DataLoader(
            test_dataset,
            batch_size=batch_size,
            shuffle=False,
            num_workers=num_workers,
            pin_memory=True if torch.cuda.is_available() else False,
            drop_last=False,
            worker_init_fn=_worker_init_fn,  # Reproducibility: seed workers
        )

    print(f"\n{'='*70}")
    print(f"DATALOADERS CREATED")
    print(f"{'='*70}")
    print(f"Train batches: {len(train_loader):,}")
    print(f"Val batches:   {len(val_loader):,}")
    if test_loader is not None:
        print(f"Test batches:  {len(test_loader):,}")
    print(f"Vocabulary:    {actual_vocab_size:,} tokens")
    print(f"Batch size:    {batch_size}")
    print(f"Sequence len:  {max_seq_len}")
    print(f"{'='*70}\n")

    if include_test:
        if return_tokenizer:
            return train_loader, val_loader, test_loader, actual_vocab_size, train_dataset
        return train_loader, val_loader, test_loader, actual_vocab_size
    if return_tokenizer:
        return train_loader, val_loader, actual_vocab_size, train_dataset
    return train_loader, val_loader, actual_vocab_size


def collate_fn(batch: List[Tuple[torch.Tensor, torch.Tensor]]) -> Tuple[torch.Tensor, torch.Tensor]:
    """
    Custom collate function for batching.

    Args:
        batch: List of (input_ids, target_ids) tuples

    Returns:
        input_batch: (B, T) batched input IDs
        target_batch: (B, T) batched target IDs
    """
    input_ids, target_ids = zip(*batch)

    input_batch = torch.stack(input_ids, dim=0)
    target_batch = torch.stack(target_ids, dim=0)

    return input_batch, target_batch


# =============================================================================
# Testing
# =============================================================================

if __name__ == '__main__':
    print("="*70)
    print("DATA PIPELINE TEST")
    print("="*70)

    if not DATASETS_AVAILABLE:
        print("\n❌ datasets not installed!")
        print("Install: pip install datasets")
        exit(1)

    # Test configuration (small for quick testing)
    max_seq_len = 64
    batch_size = 4
    vocab_size = 1000  # Restrict to 1K tokens for testing

    print(f"\n[1] Creating dataloaders...")
    print(f"    Sequence length: {max_seq_len}")
    print(f"    Batch size:      {batch_size}")
    print(f"    Vocabulary:      {vocab_size} (restricted)")

    try:
        train_loader, val_loader, actual_vocab_size = create_dataloaders(
            max_seq_len=max_seq_len,
            batch_size=batch_size,
            vocab_size=vocab_size,
            num_workers=0,
        )
        print(f"    ✓ Dataloaders created")
    except (ValueError, RuntimeError, OSError) as e:
        print(f"    ❌ Error creating dataloaders: {e}")
        raise

    # Test batch shapes
    print(f"\n[2] Testing batch shapes...")
    train_batch = next(iter(train_loader))
    input_ids, target_ids = train_batch

    print(f"    Input shape:  {input_ids.shape}")
    print(f"    Target shape: {target_ids.shape}")

    assert input_ids.shape == (batch_size, max_seq_len), "Input shape mismatch!"
    assert target_ids.shape == (batch_size, max_seq_len), "Target shape mismatch!"
    print(f"    ✓ Shapes correct")

    # Test target alignment (target[i] = input[i+1])
    print(f"\n[3] Testing target alignment...")
    # First sequence
    seq_0_input = input_ids[0]
    seq_0_target = target_ids[0]

    # Show first 10 tokens
    print(f"    Input[0]:  {seq_0_input[:10].tolist()}")
    print(f"    Target[0]: {seq_0_target[:10].tolist()}")
    print(f"    Expected:  {seq_0_input[1:11].tolist()}")

    # Verify alignment (ignoring potential padding)
    non_pad_mask = seq_0_target != train_loader.dataset.pad_token_id
    if non_pad_mask.sum() > 0:
        aligned = torch.all(seq_0_target[:-1] == seq_0_input[1:])
        if aligned:
            print(f"    ✓ Targets correctly shifted")
        else:
            print(f"    ⚠ Warning: Target alignment mismatch (may be due to padding)")

    # Test vocabulary range
    print(f"\n[4] Testing vocabulary...")
    max_token = input_ids.max().item()
    min_token = input_ids.min().item()

    print(f"    Vocabulary size: {actual_vocab_size}")
    print(f"    Token range:     [{min_token}, {max_token}]")
    print(f"    Pad token ID:    {train_loader.dataset.pad_token_id}")

    assert max_token < actual_vocab_size, f"Token {max_token} >= vocab size {actual_vocab_size}"
    assert min_token >= 0, f"Token {min_token} < 0"
    print(f"    ✓ All tokens in valid range")

    # Test validation set
    print(f"\n[5] Testing validation set...")
    val_batch = next(iter(val_loader))
    val_input, val_target = val_batch

    print(f"    Val input shape:  {val_input.shape}")
    print(f"    Val target shape: {val_target.shape}")
    print(f"    ✓ Validation batch works")

    # Dataset statistics
    print(f"\n[6] Dataset statistics:")
    print(f"    Train sequences:      {len(train_loader.dataset):,}")
    print(f"    Val sequences:        {len(val_loader.dataset):,}")
    print(f"    Train batches:        {len(train_loader):,}")
    print(f"    Val batches:          {len(val_loader):,}")
    print(f"    Total train tokens:   {len(train_loader.dataset.tokens):,}")
    print(f"    Total val tokens:     {len(val_loader.dataset.tokens):,}")

    # Estimate training time
    tokens_per_batch = batch_size * max_seq_len
    total_train_tokens = len(train_loader) * tokens_per_batch

    print(f"\n[7] Training estimates:")
    print(f"    Tokens per batch:     {tokens_per_batch:,}")
    print(f"    Total tokens/epoch:   {total_train_tokens:,}")
    print(f"    Batches per epoch:    {len(train_loader):,}")

    # Memory estimate
    # Rough estimate: embedding + activations + gradients
    mem_per_token = 4  # bytes (float32)
    model_size_mb = (actual_vocab_size * 96) * mem_per_token / 1e6  # Embedding only
    batch_mem_mb = tokens_per_batch * 96 * mem_per_token * 3 / 1e6  # Activations

    print(f"\n[8] Memory estimates (very rough):")
    print(f"    Model (embeddings):   ~{model_size_mb:.1f} MB")
    print(f"    Batch activations:    ~{batch_mem_mb:.1f} MB")
    print(f"    Estimated total:      ~{(model_size_mb + batch_mem_mb) * 2:.1f} MB (with overhead)")

    print("\n" + "="*70)
    print("✓ All data pipeline tests passed!")
    print("="*70)
    print("\nReady to train!")
    print("Next: Integrate with Trainer class in train.py")
    print("="*70)


# =============================================================================
# Backward-compatible alias: WikiTextDataset → best available implementation
# =============================================================================
# Some modules import "WikiTextDataset" generically. Route to tiktoken-based
# implementation when available, else fall back to transformers-based one.

if TIKTOKEN_AVAILABLE:
    WikiTextDataset = WikiText2TiktokenDataset
elif TRANSFORMERS_AVAILABLE:
    WikiTextDataset = WikiText2Dataset
else:
    WikiTextDataset = WikiText2ByteDataset  # Fallback: no external tokenizer