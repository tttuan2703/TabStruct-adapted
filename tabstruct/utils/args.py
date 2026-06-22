
from dataclasses import dataclass, field
from typing import Optional

@dataclass
class ModelArguments:
    """
    Arguments pertaining to which model/config/tokenizer we are going to fine-tune from.
    """
    encoding_type: str = field(
        metadata={"help": "model name"},
    )

    task: str = field(
        metadata={"help": "train or test"},
    )

    attention_type: str = field(
        metadata={"help": "sdpa"},
        default="sdpa",
    )

    input_token_structure: str = field(
        metadata={"help": "Defines the tokenization strategy for the table. Options: 'Tapex Tokens ROW IDs Cells (RIC)', 'Tokens Rows Columns Cells (RCC)', or 'No special tokens (T0)'."},
        default="T0",
    )
    mask_sparsity_level: str = field(
        metadata={"help": "Specifies the sparsity level of the attention mask. Choices range from S1 (most sparse) to S5 (least sparse). S0 indicates no sparse mask."},
        default="M0",
    )
    positional_embedding: str = field(
        metadata={"help": "Determines the type of positional embedding. Options: 'Table Positional Embedding (TPE)' or 'Cell Positional Embedding (CPE)', with CPE resetting for every cell."},
        default="CPE",
    )
    encoding_structure_bias: bool = field(
        metadata={"help": "Enables or disables the addition of structural bias to the attention mechanism."},
        default=False,
    )
    tabular_structure_embedding: str = field(
        metadata={"help": "Specifies the type of structural embedding for rows and columns. Options: 'Row-Column Embedding (E1)' or 'No Structural Embedding (E0)'."},
        default="E0",
    )
    learnable_sparse_gate: bool = field(
        default=False,
        metadata={"help": "Enable structure-constrained learnable sparse attention gates inside the fixed sparse mask."},
    )
    gate_hidden_dim: int = field(
        default=64,
        metadata={"help": "Hidden dimension used by the per-head learnable sparse gate MLP."},
    )
    gate_temperature: float = field(
        default=1.0,
        metadata={"help": "Initial temperature for the learnable sparse gate sigmoid."},
    )
    learnable_gate_temperature: bool = field(
        default=False,
        metadata={"help": "Make the gate temperature learnable per attention head."},
    )
    gate_epsilon: float = field(
        default=1e-6,
        metadata={"help": "Numerical epsilon used in log(G + epsilon)."},
    )
    sparsity_loss_weight: float = field(
        default=0.0,
        metadata={"help": "Weight for the gate sparsity regularization term."},
    )
    diversity_loss_weight: float = field(
        default=0.0,
        metadata={"help": "Weight for the multi-head gate diversity regularization term."},
    )
    entropy_loss_weight: float = field(
        default=0.0,
        metadata={"help": "Weight for the gate entropy regularization term."},
    )

    model_name_or_path: str = field(
        default=None, metadata={"help": "Path to pretrained model or model identifier from huggingface.co/models"},
    )

    config_name: Optional[str] = field(
        default=None, metadata={"help": "Pretrained config name or path if not the same as model_name"}
    )
    tokenizer_name: Optional[str] = field(
        default=None,
        metadata={
            "help": "Pretrained tokenizer name or path if not the same as model_name. "
                    "By default we use BART-large tokenizer for TAPEX-large."
        },
    )
    cache_dir: Optional[str] = field(
        default=None,
        metadata={"help": "Where to store the pretrained models downloaded from huggingface.co"},
    )
    use_fast_tokenizer: bool = field(
        default=True,
        metadata={"help": "Whether to use one of the fast tokenizer (backed by the tokenizers library) or not."},
    )
    model_revision: str = field(
        default="main",
        metadata={"help": "The specific model version to use (can be a branch name, tag name or commit id)."},
    )
    use_auth_token: bool = field(
        default=False,
        metadata={
            "help": "Will use the token generated when running `transformers-cli login` (necessary to use this script "
                    "with private models)."
        },
    )
    
    tapas_path: str = field(
        default="google/tapas-base",
    )

@dataclass
class DataTrainingArguments:
    """
    Arguments pertaining to what data we are going to input our model for training and eval.
    """

    dataset_name: Optional[str] = field(
        default=None, metadata={"help": "The name of the dataset to use (via the datasets library)."}
    )
    dataset_config_name: Optional[str] = field(
        default=None, metadata={"help": "The configuration name of the dataset to use (via the datasets library)."}
    )
    train_file: Optional[str] = field(
        default=None, metadata={"help": "The input training data file (a jsonlines or csv file)."}
    )
    validation_file: Optional[str] = field(
        default=None,
        metadata={
            "help": "An optional input evaluation data file to evaluate the metrics (rouge) on "
                    "(a jsonlines or csv file)."
        },
    )
    test_file: Optional[str] = field(
        default=None,
        metadata={
            "help": "An optional input test data file to evaluate the metrics (rouge) on " "(a jsonlines or csv file)."
        },
    )
    overwrite_cache: bool = field(
        default=False, metadata={"help": "Overwrite the cached training and evaluation sets"}
    )
    
    preprocessing_num_workers: Optional[int] = field(
        default=None,
        metadata={"help": "The number of processes to use for the preprocessing."},
    )
    max_source_length: Optional[int] = field(
        default=512,
        metadata={
            "help": "The maximum total input sequence length after tokenization. Sequences longer "
                    "than this will be truncated, sequences shorter will be padded."
        },
    )
    
    max_target_length: Optional[int] = field(
        default=128,
        metadata={
            "help": "The maximum total sequence length for target text after tokenization. Sequences longer "
                    "than this will be truncated, sequences shorter will be padded."
        },
    )

    val_max_target_length: Optional[int] = field(
        default=128,
        metadata={
            "help": "The maximum total sequence length for validation target text after tokenization. Sequences longer "
                    "than this will be truncated, sequences shorter will be padded. Will default to `max_target_length`."
                    "This argument is also used to override the ``max_length`` param of ``model.generate``, which is used "
                    "during ``evaluate`` and ``predict``."
        },
    )

    pad_to_max_length: bool = field(
        default=False,
        metadata={
            "help": "Whether to pad all samples to model maximum sentence length. "
                    "If False, will pad the samples dynamically when batching to the maximum length in the batch. More "
                    "efficient on GPU but very bad for TPU."
        },
    )

    ignore_pad_token_for_loss: bool = field(
        default=True,
        metadata={
            "help": "Whether to ignore the tokens corresponding to padded labels in the loss computation or not."
        },
    )

    num_beams: Optional[int] = field(
        default=5,
        metadata={
            "help": "Number of beams to use for evaluation. This argument will be passed to ``model.generate``, "
                    "which is used during ``evaluate`` and ``predict``."
        },
    )



def __post_init__(self):

    if self.dataset_name is None and self.train_file is None and self.validation_file is None:
        raise ValueError("Need either a dataset name or a training/validation file.")
    else:
        if self.train_file is not None:
            extension = self.train_file.split(".")[-1]
            assert extension in ["csv", "json"], "`train_file` should be a csv or a json file."
        if self.validation_file is not None:
            extension = self.validation_file.split(".")[-1]
            assert extension in ["csv", "json"], "`validation_file` should be a csv or a json file."
    if self.val_max_target_length is None:
        self.val_max_target_length = self.max_target_length
