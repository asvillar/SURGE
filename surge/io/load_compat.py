"""Compatibility loaders for models saved with older sklearn/PyTorch versions."""

from __future__ import annotations

import logging
from pathlib import Path
from typing import Any, Optional

import joblib

LOG = logging.getLogger(__name__)

# Track if sklearn patch was applied (avoid applying twice)
_SKLEARN_PATCH_APPLIED = False


def _apply_sklearn_compat_patch() -> None:
    """Patch sklearn tree classes to handle missing monotonic_cst in old pickles (1.3.x -> 1.4+)."""
    global _SKLEARN_PATCH_APPLIED
    if _SKLEARN_PATCH_APPLIED:
        return
    try:
        import sklearn.tree

        def _make_compat_setstate(orig_setstate: Any) -> Any:
            def _compat_setstate(self: Any, state: Any) -> Any:
                if isinstance(state, dict) and "monotonic_cst" not in state:
                    state = dict(state)
                    state["monotonic_cst"] = None
                return orig_setstate(self, state)

            return _compat_setstate

        for cls_name in ("DecisionTreeRegressor", "DecisionTreeClassifier"):
            cls = getattr(sklearn.tree, cls_name, None)
            if cls is None or not hasattr(cls, "__setstate__"):
                continue
            cls.__setstate__ = _make_compat_setstate(cls.__setstate__)
        _SKLEARN_PATCH_APPLIED = True
    except Exception as e:
        LOG.debug("Could not apply sklearn compat patch: %s", e)


def _load_torch_model(
    path: Path, model_entry: dict, *, for_finetune: bool = False
) -> Optional[Any]:
    """Load a PyTorch model saved with torch.save (avoids joblib/pickle protocol 0 issues)."""
    try:
        import torch
        import torch.nn as nn  # noqa: F401  (availability probe)
        import numpy as np  # noqa: F401
        from sklearn.preprocessing import StandardScaler  # noqa: F401
    except ImportError:
        return None
    try:
        checkpoint = torch.load(path, map_location="cpu", weights_only=False)
    except Exception:
        return None
    if not isinstance(checkpoint, dict):
        return None

    # Format 1: PyTorchMLPModel (model_state_dict + model_config)
    if "model_state_dict" in checkpoint and "model_config" in checkpoint:
        try:
            from ..model.pytorch_impl import PyTorchMLPModel
            from ..model.pytorch import PyTorchMLPAdapter

            model = PyTorchMLPModel()
            model.load(str(path))
            if for_finetune:
                adapter = PyTorchMLPAdapter()
                adapter._model = model
                return adapter
            return _TorchAdapter(model)
        except Exception as e:
            LOG.debug("Could not load PyTorchMLPModel format: %s", e)
            # Fallback: infer architecture from state_dict (config may have wrong hidden_layers)
            try:
                return _reconstruct_from_model_state_dict(checkpoint)
            except Exception as e2:
                LOG.debug("Could not reconstruct from model_state_dict: %s", e2)

    # Format 2: state_dict + params (generic/custom MLP with net, scalers)
    if "state_dict" in checkpoint and "params" in checkpoint:
        try:
            return _reconstruct_net_mlp(checkpoint)
        except Exception as e:
            LOG.debug("Could not reconstruct state_dict+params format: %s", e)

    return None


def _infer_hidden_layers_from_state_dict(state_dict: dict) -> list:
    """Infer hidden layer sizes from PyTorchMLP state_dict (network.0, network.3, network.6)."""
    out = []
    # network.0.weight: (h1, in), network.3.weight: (h2, h1), network.6.weight: (out, h2)
    for key in ["network.0.weight", "network.3.weight"]:
        if key in state_dict:
            w = state_dict[key]
            out.append(int(w.shape[0]))
    return out


def _reconstruct_from_model_state_dict(checkpoint: dict) -> Any:
    """Reconstruct MLP from model_state_dict + model_config when config has wrong hidden_layers."""
    import torch
    import torch.nn as nn
    import numpy as np

    state_dict = checkpoint["model_state_dict"]
    config = checkpoint.get("model_config", {})
    hidden_layers = _infer_hidden_layers_from_state_dict(state_dict)
    if not hidden_layers:
        raise ValueError("Could not infer hidden_layers from state_dict")
    input_size = config.get("input_size")
    output_size = config.get("output_size")
    if input_size is None or output_size is None:
        raise ValueError("model_config missing input_size or output_size")
    dropout_rate = config.get("dropout_rate", 0.1)
    activation_fn = config.get("activation_fn")
    if activation_fn is None or not callable(getattr(activation_fn, "__call__", None)):
        activation_fn = nn.ReLU

    layers = []
    prev = input_size
    for h in hidden_layers:
        layers.append(nn.Linear(prev, h))
        layers.append(activation_fn() if callable(activation_fn) else activation_fn)
        if dropout_rate > 0:
            layers.append(nn.Dropout(dropout_rate))
        prev = h
    layers.append(nn.Linear(prev, output_size))

    class _NetMLP(nn.Module):
        def __init__(self):
            super().__init__()
            self.network = nn.Sequential(*layers)

        def forward(self, x):
            return self.network(x)

        def predict(self, X):
            if isinstance(X, np.ndarray):
                X = torch.tensor(X, dtype=torch.float32)
            self.eval()
            with torch.no_grad():
                out = self.forward(X)
            return out.cpu().numpy()

    model = _NetMLP()
    model.load_state_dict(state_dict, strict=True)
    # Model expects scaled X (from run's input_scaler), returns scaled y (caller uses output_scaler)
    return _TorchAdapter(model)


def _TorchAdapter(model: Any) -> Any:
    """Thin wrapper with predict for torch models."""

    class _Adapter:
        def __init__(self, m: Any):
            self._model = m

        def predict(self, X: Any) -> Any:
            return self._model.predict(X)

    return _Adapter(model)


def _reconstruct_net_mlp(checkpoint: dict) -> Optional[Any]:
    """Reconstruct MLP from state_dict + params (net architecture).
    Expects X in scaled space (run's input_scaler); returns predictions in scaled space.
    """
    import torch
    import torch.nn as nn
    import numpy as np

    params = checkpoint["params"]
    state_dict = checkpoint["state_dict"]
    input_dim = params.get("input_dim")
    output_dim = params.get("output_dim")
    hidden_layers = params.get("hidden_layers", (64, 32))
    if isinstance(hidden_layers, tuple):
        hidden_layers = list(hidden_layers)
    dropout = params.get("dropout", 0.1)
    activation = params.get("activation", "relu")

    if input_dim is None or output_dim is None:
        return None

    act_map = {"relu": nn.ReLU, "tanh": nn.Tanh, "leaky_relu": nn.LeakyReLU}
    act_fn = act_map.get(activation, nn.ReLU)

    layers = []
    prev = input_dim
    for h in hidden_layers:
        layers.append(nn.Linear(prev, h))
        layers.append(act_fn())
        if dropout > 0:
            layers.append(nn.Dropout(dropout))
        prev = h
    layers.append(nn.Linear(prev, output_dim))

    class _NetMLP(nn.Module):
        def __init__(self):
            super().__init__()
            self.net = nn.Sequential(*layers)

        def forward(self, x):
            return self.net(x)

        def predict(self, X):
            if isinstance(X, np.ndarray):
                X = torch.tensor(X, dtype=torch.float32)
            self.eval()
            with torch.no_grad():
                out = self.forward(X)
            return out.cpu().numpy()

    model = _NetMLP()
    model.load_state_dict(state_dict, strict=True)
    return _TorchAdapter(model)


def _load_dino_probe(obj: dict, path: Path) -> Any:
    """Rebuild a ``pytorch.dino_linear_probe`` adapter from a saved artifact."""
    try:
        import torch  # noqa: F401
        import sklearn  # noqa: F401
    except ImportError as e:
        raise ImportError(
            "Loading a surge.dino_linear_probe artifact requires torch and "
            "scikit-learn (pip install torch scikit-learn)"
        ) from e
    from ..model import MODEL_REGISTRY
    from ..model.backends.dino_linear_probe import resolve_extractor

    params = dict(obj.get("params") or {})
    extractor_id = obj.get("extractor_id")
    # Restore the backbone that produced the saved features (raises for an
    # unregistered custom extractor instead of substituting DINOv2).
    params["hub_loader"] = resolve_extractor(extractor_id)
    if extractor_id is not None:
        params["extractor_id"] = extractor_id
    adapter = MODEL_REGISTRY.create("pytorch.dino_linear_probe", **params)
    adapter.load(str(path))
    adapter.mark_fitted()
    return adapter


_RESIDUAL_MLP_KEYS = {"state_dict", "scaler_X", "scaler_y", "config"}


def _load_residual_mlp(path: Path) -> Any:
    """Rebuild a ``pytorch.residual_mlp`` adapter from its joblib payload
    (``state_dict`` + scalers + ``config``), which is not a torch checkpoint."""
    from ..model import MODEL_REGISTRY

    adapter = MODEL_REGISTRY.create("pytorch.residual_mlp")
    adapter.load(str(path))
    adapter.mark_fitted()
    return adapter


def load_model_compat(
    model_path: Path,
    model_entry: Optional[dict] = None,
    *,
    for_finetune: bool = False,
) -> Any:
    """
    Load a model with compatibility for older sklearn (monotonic_cst) and PyTorch (persistent IDs).

    For PyTorch models (backend pytorch or for_finetune), tries torch.load first to avoid
    joblib "persistent IDs in protocol 0" errors. Falls back to joblib for sklearn models.
    When for_finetune=True, returns a full PyTorchMLPAdapter (with fit) for torch models.
    """
    _apply_sklearn_compat_patch()
    model_entry = model_entry or {}
    backend = model_entry.get("backend", "")

    # For torch models, try torch format first (avoids joblib persistent ID errors)
    if backend == "pytorch" or (for_finetune and backend != "sklearn"):
        adapter = _load_torch_model(model_path, model_entry, for_finetune=for_finetune)
        if adapter is not None:
            return adapter

    # Try joblib (works for sklearn models and some torch if no protocol 0 issues)
    try:
        obj = joblib.load(model_path)
        if isinstance(obj, dict) and str(obj.get("format", "")).startswith(
            "surge.dino_linear_probe"
        ):
            return _load_dino_probe(obj, Path(model_path))
        if isinstance(obj, dict) and _RESIDUAL_MLP_KEYS <= set(obj):
            return _load_residual_mlp(Path(model_path))
        # If we got a dict (torch checkpoint) or thin adapter without fit, use torch loader
        if isinstance(obj, dict) and "model_state_dict" in obj:
            adapter = _load_torch_model(model_path, model_entry, for_finetune=for_finetune)
            if adapter is not None:
                return adapter
        if for_finetune and hasattr(obj, "_model") and not hasattr(obj, "fit"):
            adapter = _load_torch_model(model_path, model_entry, for_finetune=True)
            if adapter is not None:
                return adapter
        return obj
    except Exception:
        # Fallback: try torch format (for PyTorch models saved with adapter.save)
        adapter = _load_torch_model(model_path, model_entry, for_finetune=for_finetune)
        if adapter is not None:
            return adapter
        raise
