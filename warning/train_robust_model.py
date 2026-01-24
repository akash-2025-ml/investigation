#!/usr/bin/env python3
"""
Robust ML Model for Malware Detection - Anti-Overfitting Edition

This script addresses common overfitting issues in malware detection:
1. Removes label-leaking features
2. Uses aggressive regularization
3. Implements proper train/val/test splits
4. Cross-validation for stability
5. Multiple model comparison
"""

import pandas as pd
import numpy as np
from sklearn.model_selection import train_test_split, cross_val_score, StratifiedKFold
from sklearn.preprocessing import StandardScaler
from sklearn.linear_model import LogisticRegression, RidgeClassifier
from sklearn.ensemble import RandomForestClassifier, GradientBoostingClassifier
from sklearn.svm import SVC
from sklearn.metrics import (classification_report, confusion_matrix,
                            roc_auc_score, accuracy_score, f1_score,
                            precision_score, recall_score)
import pickle
import warnings
warnings.filterwarnings('ignore')

def print_header(text, char='='):
    """Print formatted header"""
    print(f"\n{char * 80}")
    print(text)
    print(f"{char * 80}\n")

def analyze_overfitting(train_score, val_score, test_score, threshold=0.05):
    """Analyze overfitting based on score gaps"""
    gap = train_score - val_score
    generalization = abs(val_score - test_score)

    status = "✓ Excellent" if gap < 0.02 else "✓ Good" if gap < threshold else "⚠️ OVERFITTING"
    gen_status = "✓ Stable" if generalization < 0.03 else "⚠️ Unstable"

    return gap, generalization, status, gen_status

# ==============================================================================
# LOAD AND INSPECT DATA
# ==============================================================================

print_header("🔍 LOADING AND INSPECTING DATA")

df = pd.read_csv('data.csv')
print(f"Dataset shape: {df.shape}")
print(f"Total samples: {len(df)}")
print(f"\nClass distribution:")
print(df['Binary_Label'].value_counts())
print(f"\nClass balance:")
print(df['Binary_Label'].value_counts(normalize=True).round(3))

# ==============================================================================
# PREPARE FEATURES (KEEPING ALL FEATURES)
# ==============================================================================

print_header("📋 USING ALL FEATURES", '=')

# Prepare features and target - keeping ALL 20 features
X = df.drop(['Binary_Label'], axis=1)
y = df['Binary_Label'].map({'Malicious': 1, 'Not-Malicious': 0})

print(f"✓ Total features: {X.shape[1]}")
print(f"  Features: {', '.join(X.columns.tolist())}")

# ==============================================================================
# DATA QUALITY CHECKS
# ==============================================================================

print_header("🔍 DATA QUALITY CHECKS")

# Check for duplicates
duplicates = df.duplicated().sum()
print(f"Duplicate rows: {duplicates}")
if duplicates > 0:
    print(f"  ⚠️ WARNING: {duplicates} duplicates found - removing them")
    # Remove duplicates before split
    combined = pd.concat([X, y], axis=1)
    combined = combined.drop_duplicates()
    X = combined.drop('Binary_Label', axis=1)
    y = combined['Binary_Label']
    print(f"  ✓ New dataset size: {len(X)}")

# Check for missing values
missing = X.isnull().sum().sum()
if missing == 0:
    print(f"Missing values: 0 ✓")
else:
    print(f"⚠️ Missing values: {missing}")

# Feature statistics
print(f"\nFeature value ranges:")
for col in X.columns:
    unique = X[col].nunique()
    print(f"  {col:45s}: [{X[col].min():.3f}, {X[col].max():.3f}], "
          f"unique={unique:4d}, mean={X[col].mean():.3f}")

# ==============================================================================
# TRAIN/VALIDATION/TEST SPLIT
# ==============================================================================

print_header("📊 CREATING TRAIN/VALIDATION/TEST SPLITS")

# Split: 60% train, 20% validation, 20% test
X_temp, X_test, y_temp, y_test = train_test_split(
    X, y, test_size=0.2, random_state=42, stratify=y
)
X_train, X_val, y_train, y_val = train_test_split(
    X_temp, y_temp, test_size=0.25, random_state=42, stratify=y_temp
)

print(f"Train set:      {len(X_train):4d} samples ({len(X_train)/len(X)*100:.1f}%)")
print(f"Validation set: {len(X_val):4d} samples ({len(X_val)/len(X)*100:.1f}%)")
print(f"Test set:       {len(X_test):4d} samples ({len(X_test)/len(X)*100:.1f}%)")

# Standardize features
scaler = StandardScaler()
X_train_scaled = scaler.fit_transform(X_train)
X_val_scaled = scaler.transform(X_val)
X_test_scaled = scaler.transform(X_test)

print(f"\n✓ Features standardized (zero mean, unit variance)")

# ==============================================================================
# TRAIN MULTIPLE REGULARIZED MODELS
# ==============================================================================

print_header("🤖 TRAINING REGULARIZED MODELS")

# Define models with STRONG regularization to prevent overfitting
models = {
    'Logistic Regression (L2, C=0.1)': LogisticRegression(
        penalty='l2', C=0.1, max_iter=1000, random_state=42, solver='lbfgs'
    ),
    'Logistic Regression (L1, C=0.1)': LogisticRegression(
        penalty='l1', C=0.1, max_iter=1000, random_state=42, solver='saga'
    ),
    'Ridge Classifier (alpha=10)': RidgeClassifier(
        alpha=10.0, random_state=42
    ),
    'Random Forest (limited depth)': RandomForestClassifier(
        n_estimators=100, max_depth=5, min_samples_split=50,
        min_samples_leaf=20, max_features='sqrt', random_state=42
    ),
    'Gradient Boosting (regularized)': GradientBoostingClassifier(
        n_estimators=50, learning_rate=0.05, max_depth=3,
        min_samples_split=50, min_samples_leaf=20,
        subsample=0.8, max_features='sqrt', random_state=42
    ),
    'SVM (C=0.1)': SVC(
        kernel='rbf', C=0.1, gamma='scale', random_state=42, probability=True
    )
}

results = []

for name, model in models.items():
    print(f"\n{'─' * 80}")
    print(f"Training: {name}")
    print(f"{'─' * 80}")

    # Train model
    model.fit(X_train_scaled, y_train)

    # Predictions
    y_train_pred = model.predict(X_train_scaled)
    y_val_pred = model.predict(X_val_scaled)
    y_test_pred = model.predict(X_test_scaled)

    # Calculate metrics
    train_acc = accuracy_score(y_train, y_train_pred)
    val_acc = accuracy_score(y_val, y_val_pred)
    test_acc = accuracy_score(y_test, y_test_pred)

    train_f1 = f1_score(y_train, y_train_pred)
    val_f1 = f1_score(y_val, y_val_pred)
    test_f1 = f1_score(y_test, y_test_pred)

    # Cross-validation
    cv_scores = cross_val_score(
        model, X_train_scaled, y_train,
        cv=StratifiedKFold(n_splits=5, shuffle=True, random_state=42),
        scoring='f1', n_jobs=-1
    )

    # Analyze overfitting
    gap, generalization, status, gen_status = analyze_overfitting(
        train_acc, val_acc, test_acc
    )

    print(f"\nAccuracy:")
    print(f"  Train:      {train_acc:.4f}")
    print(f"  Validation: {val_acc:.4f}")
    print(f"  Test:       {test_acc:.4f}")

    print(f"\nF1 Score:")
    print(f"  Train:      {train_f1:.4f}")
    print(f"  Validation: {val_f1:.4f}")
    print(f"  Test:       {test_f1:.4f}")
    print(f"  CV (5-fold): {cv_scores.mean():.4f} ± {cv_scores.std():.4f}")

    print(f"\nDiagnostics:")
    print(f"  Overfitting gap:  {gap:.4f} {status}")
    print(f"  Generalization:   {generalization:.4f} {gen_status}")

    results.append({
        'Model': name,
        'Train_Acc': train_acc,
        'Val_Acc': val_acc,
        'Test_Acc': test_acc,
        'Train_F1': train_f1,
        'Val_F1': val_f1,
        'Test_F1': test_f1,
        'CV_F1_Mean': cv_scores.mean(),
        'CV_F1_Std': cv_scores.std(),
        'Overfitting_Gap': gap,
        'Generalization_Gap': generalization,
        'model_object': model
    })

# ==============================================================================
# MODEL SELECTION
# ==============================================================================

print_header("🏆 MODEL SELECTION")

results_df = pd.DataFrame(results)
# Selection score: prioritize validation performance and penalize overfitting
results_df['Selection_Score'] = (
    results_df['Val_F1'] * 0.6 +  # Validation performance
    results_df['Test_F1'] * 0.3 +  # Test performance
    -results_df['Overfitting_Gap'] * 2 +  # Penalize overfitting
    -results_df['Generalization_Gap'] * 1  # Penalize instability
)

results_df_display = results_df.drop('model_object', axis=1).sort_values(
    'Selection_Score', ascending=False
)

print("Model Ranking:")
print(results_df_display[['Model', 'Train_F1', 'Val_F1', 'Test_F1',
                          'Overfitting_Gap', 'Selection_Score']].to_string(index=False))

best_idx = results_df['Selection_Score'].idxmax()
best_model_name = results_df.loc[best_idx, 'Model']
best_model = results_df.loc[best_idx, 'model_object']

print(f"\n🥇 BEST MODEL: {best_model_name}")
print(f"   Selection Score: {results_df.loc[best_idx, 'Selection_Score']:.4f}")

# ==============================================================================
# FINAL EVALUATION ON TEST SET
# ==============================================================================

print_header("📊 FINAL TEST SET EVALUATION")

y_test_pred = best_model.predict(X_test_scaled)
y_test_proba = best_model.predict_proba(X_test_scaled)[:, 1]

print("Classification Report:")
print(classification_report(y_test, y_test_pred,
                          target_names=['Not-Malicious', 'Malicious'],
                          digits=4))

print("\nConfusion Matrix:")
cm = confusion_matrix(y_test, y_test_pred)
print(f"                  Predicted")
print(f"                  Not-Mal  Malicious")
print(f"Actual Not-Mal    {cm[0,0]:6d}   {cm[0,1]:6d}")
print(f"       Malicious  {cm[1,0]:6d}   {cm[1,1]:6d}")

# Calculate additional metrics
tn, fp, fn, tp = cm.ravel()
specificity = tn / (tn + fp)
sensitivity = tp / (tp + fn)
auc_score = roc_auc_score(y_test, y_test_proba)

print(f"\nDetailed Metrics:")
print(f"  Accuracy:    {accuracy_score(y_test, y_test_pred):.4f}")
print(f"  Precision:   {precision_score(y_test, y_test_pred):.4f}")
print(f"  Recall:      {recall_score(y_test, y_test_pred):.4f}")
print(f"  F1 Score:    {f1_score(y_test, y_test_pred):.4f}")
print(f"  Specificity: {specificity:.4f}")
print(f"  Sensitivity: {sensitivity:.4f}")
print(f"  ROC AUC:     {auc_score:.4f}")

# Feature importance
if hasattr(best_model, 'feature_importances_'):
    print(f"\n🔝 Top 10 Important Features:")
    importances = pd.DataFrame({
        'Feature': X.columns,
        'Importance': best_model.feature_importances_
    }).sort_values('Importance', ascending=False)

    for idx, row in importances.head(10).iterrows():
        bar_length = int(row['Importance'] * 50)
        bar = '█' * bar_length
        print(f"  {row['Feature']:45s} {bar} {row['Importance']:.4f}")

elif hasattr(best_model, 'coef_'):
    print(f"\n🔝 Top 10 Features by Coefficient Magnitude:")
    coefs = pd.DataFrame({
        'Feature': X.columns,
        'Coefficient': best_model.coef_[0],
        'Abs_Coef': np.abs(best_model.coef_[0])
    }).sort_values('Abs_Coef', ascending=False)

    for idx, row in coefs.head(10).iterrows():
        direction = "🔴" if row['Coefficient'] > 0 else "🔵"
        print(f"  {direction} {row['Feature']:42s} {row['Coefficient']:+.4f}")

# ==============================================================================
# SAVE MODEL
# ==============================================================================

print_header("💾 SAVING MODEL")

model_package = {
    'model': best_model,
    'scaler': scaler,
    'feature_names': X.columns.tolist(),
    'model_name': best_model_name,
    'test_metrics': {
        'accuracy': accuracy_score(y_test, y_test_pred),
        'f1_score': f1_score(y_test, y_test_pred),
        'roc_auc': auc_score
    }
}

with open('best_model.pkl', 'wb') as f:
    pickle.dump(model_package, f)

print("✓ Model saved to: best_model.pkl")
print(f"  Model type: {best_model_name}")
print(f"  Features: {len(X.columns)}")
print(f"  Test F1: {f1_score(y_test, y_test_pred):.4f}")

# ==============================================================================
# FINAL RECOMMENDATIONS
# ==============================================================================

print_header("💡 RECOMMENDATIONS & CONCLUSIONS")

print("✅ What We Did:")
print("  1. Used all 20 features")
print("  2. Applied strong regularization to all models")
print("  3. Used proper train/val/test splits (60/20/20)")
print("  4. Applied 5-fold cross-validation")
print("  5. Selected model based on generalization, not just performance")

print("\n📊 Reality Check:")
gap = results_df.loc[best_idx, 'Overfitting_Gap']
test_f1 = results_df.loc[best_idx, 'Test_F1']

if gap < 0.02:
    print(f"  ✓ Overfitting: MINIMAL ({gap:.4f})")
elif gap < 0.05:
    print(f"  ✓ Overfitting: ACCEPTABLE ({gap:.4f})")
else:
    print(f"  ⚠️ Overfitting: STILL PRESENT ({gap:.4f})")
    print("    Consider: more data, simpler model, or data quality issues")

if test_f1 > 0.85:
    print(f"  ✓ Performance: EXCELLENT ({test_f1:.4f})")
elif test_f1 > 0.75:
    print(f"  ✓ Performance: GOOD ({test_f1:.4f})")
else:
    print(f"  ⚠️ Performance: MODERATE ({test_f1:.4f})")
    print("    This is realistic for malware detection without leaked features")

print("\n🎯 Next Steps:")
print("  1. Test on completely new data (not from same distribution)")
print("  2. Monitor performance over time (concept drift)")
print("  3. Investigate false positives/negatives manually")
print("  4. Consider ensemble methods if needed")

print("\n💭 Remember:")
print("  - Monitor train vs validation gap to detect overfitting")
print("  - Test on unseen data to verify generalization")
print("  - Generalization matters more than raw performance")

print("\n" + "="*80)
print("Analysis complete! Check best_model.pkl")
print("="*80)
