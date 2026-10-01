import json
from pathlib import Path

import numpy as np
from sklearn.linear_model import LogisticRegression
from sklearn.metrics import (
    accuracy_score,
    jaccard_score,
    multilabel_confusion_matrix,
    zero_one_loss,
)
from sklearn.model_selection import train_test_split
from sklearn.multiclass import OneVsRestClassifier
from sklearn.multioutput import ClassifierChain
from sklearn.preprocessing import MultiLabelBinarizer
from sklearn.svm import LinearSVC


def pred_image_categories(sub_name, data_dir):
    """
    Predict 720 image categories from CLIP embeddings.
    Each image is assigned to only one category.

    Parameters
    ----------
    sub_name : str
    data_dir : str
    """
    stim_vec = np.loadtxt(
        Path(data_dir, "encoding-inputs", f"{sub_name}_stim_labels.txt"),
        dtype=np.str_,
    )
    X_matrix = np.load(
        Path(data_dir, "encoding-inputs", f"{sub_name}_stim_features.npy")
    )

    stim_cat = np.asarray([sv.rsplit("_", 1)[0] for sv in stim_vec])
    # lb = LabelBinarizer().fit(stim_cat)
    # cat_y = lb.transform(stim_cat)
    X_train, X_test, y_train, y_test = train_test_split(
        X_matrix, stim_cat, test_size=0.33, random_state=2
    )

    # clf = OneVsRestClassifier(LogisticRegression())  # 0.933
    clf = LinearSVC()
    y_pred = clf.fit(X_train, y_train).predict(X_test)
    y_score = accuracy_score(y_test, y_pred)  # 0.974

    cfm = multilabel_confusion_matrix(y_test, y_pred)

    return cfm, y_score


def pred_THINGSPlus_categories(sub_name, data_dir):
    """
    Predict multi-label 53 THINGSPlus image categories from CLIP embeddings.
    Each image may be assigned to multiple categories.

    Parameters
    ----------
    sub_name : str
    data_dir : str
    """
    with open(Path(data_dir, "encoding-inputs", "category53_mapping.json")) as f:
        cat_dict = json.load(f)

    stim_vec = np.loadtxt(
        Path(data_dir, "encoding-inputs", f"{sub_name}_stim_labels.txt"),
        dtype=np.str_,
    )
    X_matrix = np.load(
        Path(data_dir, "encoding-inputs", f"{sub_name}_stim_features.npy")
    )

    cat53_stim_mask_ = [True if sv in cat_dict.keys() else False for sv in stim_vec]
    cat53_X = X_matrix[cat53_stim_mask_]

    cat53_dense_labels_ = []
    for sv in stim_vec[cat53_stim_mask_]:
        cat53_dense_labels_.append(cat_dict.get(sv))

    mlb = MultiLabelBinarizer().fit(cat53_dense_labels_)
    cat53_y = mlb.transform(cat53_dense_labels_)
    X_train, X_test, y_train, y_test = train_test_split(
        cat53_X, cat53_y, test_size=0.2, random_state=2
    )

    # run classification analysis
    clf = OneVsRestClassifier(LogisticRegression())
    y_pred = clf.fit(X_train, y_train).predict(X_test)
    cfm = multilabel_confusion_matrix(y_test, y_pred)

    # ovr_loss = zero_one_loss(y_test, y_pred)  # 0.332
    ovr_score = jaccard_score(y_test, y_pred, average="samples")  # 0.751

    # Compare with ensemble of binary classifiers
    # See : https://scikit-learn.org/stable/auto_examples/multioutput/plot_classifier_chain_yeast.html#sphx-glr-auto-examples-multioutput-plot-classifier-chain-yeast-py
    chains = [
        ClassifierChain(LogisticRegression(), order="random", random_state=i)
        for i in range(10)
    ]
    for chain in chains:
        chain.fit(X_train, y_train)

    y_pred_chains = np.array([chain.predict(X_test) for chain in chains])
    chain_scores = [
        jaccard_score(y_test, y_pred_chain, average="samples")
        for y_pred_chain in y_pred_chains
    ]

    y_pred_ensemble = y_pred_chains.mean(axis=0)
    # taking the average of binary values means we have to threshold
    ensemble_score = jaccard_score(
        y_test, y_pred_ensemble >= 0.5, average="samples"
    )  # 0.786

    return cfm, ovr_score, chain_scores, ensemble_score
