import pandas as pd
import numpy as np
from datetime import datetime, timedelta
import streamlit as st
import os



class InventoryForecaster:
    """Comprehensive inventory forecasting with regression and LSTM models"""

    def __init__(self, _db_manager):
        self._db = _db_manager

    def prepare_data_for_regression(self):
        """Prepare inventory data for regression analysis"""
        conn = self._db.get_connection()

        # Get comprehensive inventory and consumption data
        query = """
            SELECT
                i.id,
                i.drug_name,
                i.category,
                i.current_stock,
                i.minimum_stock,
                i.unit_price,
                i.per_tablet_price,
                i.per_sheet_price,
                i.tablets_per_sheet,
                COALESCE(AVG(cp.quantity_consumed), 0) as avg_daily_consumption,
                COALESCE(SUM(cp.quantity_consumed), 0) as total_consumption,
                COUNT(cp.id) as days_tracked
            FROM inventory i
            LEFT JOIN consumption_patterns cp ON i.id = cp.drug_id
            GROUP BY i.id
            HAVING days_tracked > 0
        """

        df = pd.read_sql_query(query, conn)
        conn.close()

        if len(df) < 10:
            return None

        # Feature engineering
        df["stock_turnover"] = df["total_consumption"] / (df["current_stock"] + 1)
        df["days_until_stockout"] = df["current_stock"] / (
            df["avg_daily_consumption"] + 0.1
        )
        df["price_category"] = pd.cut(
            df["per_tablet_price"],
            bins=5,
            labels=["Very Low", "Low", "Medium", "High", "Very High"],
        )
        df["stock_status"] = df.apply(
            lambda x: "Low" if x["current_stock"] <= x["minimum_stock"] else "Normal",
            axis=1,
        )

        return df

    def train_regression_models(self):
        """Train all three regression models and compare them"""
        df = self.prepare_data_for_regression()

        if df is None or len(df) < 10:
            return None

        # Prepare features and target
        X = df[
            [
                "avg_daily_consumption",
                "minimum_stock",
                "per_tablet_price",
                "tablets_per_sheet",
            ]
        ].fillna(0)
        y = df["current_stock"]

        from sklearn.linear_model import LinearRegression, Ridge, Lasso, ElasticNet
        from sklearn.preprocessing import PolynomialFeatures, StandardScaler
        from sklearn.model_selection import train_test_split
        from sklearn.metrics import mean_squared_error, r2_score, mean_absolute_error

        # Split data
        X_train, X_test, y_train, y_test = train_test_split(
            X, y, test_size=0.2, random_state=42
        )

        # Standardize features
        scaler = StandardScaler()
        X_train_scaled = scaler.fit_transform(X_train)
        X_test_scaled = scaler.transform(X_test)

        results = {}

        # 1. Linear Regression
        lr_model = LinearRegression()
        lr_model.fit(X_train_scaled, y_train)
        lr_pred = lr_model.predict(X_test_scaled)

        results["linear"] = {
            "model": lr_model,
            "predictions": lr_pred,
            "r2": r2_score(y_test, lr_pred),
            "mae": mean_absolute_error(y_test, lr_pred),
            "rmse": np.sqrt(mean_squared_error(y_test, lr_pred)),
            "y_test": y_test,
        }

        # 2. Polynomial Regression (degree 2)
        poly_features = PolynomialFeatures(degree=2)
        X_train_poly = poly_features.fit_transform(X_train_scaled)
        X_test_poly = poly_features.transform(X_test_scaled)

        poly_model = LinearRegression()
        poly_model.fit(X_train_poly, y_train)
        poly_pred = poly_model.predict(X_test_poly)

        results["polynomial"] = {
            "model": poly_model,
            "predictions": poly_pred,
            "r2": r2_score(y_test, poly_pred),
            "mae": mean_absolute_error(y_test, poly_pred),
            "rmse": np.sqrt(mean_squared_error(y_test, poly_pred)),
            "y_test": y_test,
        }

        # 3. Ridge Regression
        ridge_model = Ridge(alpha=1.0)
        ridge_model.fit(X_train_scaled, y_train)
        ridge_pred = ridge_model.predict(X_test_scaled)

        results["ridge"] = {
            "model": ridge_model,
            "predictions": ridge_pred,
            "r2": r2_score(y_test, ridge_pred),
            "mae": mean_absolute_error(y_test, ridge_pred),
            "rmse": np.sqrt(mean_squared_error(y_test, ridge_pred)),
            "y_test": y_test,
        }

        # 4. Lasso Regression
        lasso_model = Lasso(alpha=0.1)
        lasso_model.fit(X_train_scaled, y_train)
        lasso_pred = lasso_model.predict(X_test_scaled)

        results["lasso"] = {
            "model": lasso_model,
            "predictions": lasso_pred,
            "r2": r2_score(y_test, lasso_pred),
            "mae": mean_absolute_error(y_test, lasso_pred),
            "rmse": np.sqrt(mean_squared_error(y_test, lasso_pred)),
            "y_test": y_test,
        }

        # 5. ElasticNet Regression
        en_model = ElasticNet(alpha=0.1, l1_ratio=0.5)
        en_model.fit(X_train_scaled, y_train)
        en_pred = en_model.predict(X_test_scaled)

        results["elasticnet"] = {
            "model": en_model,
            "predictions": en_pred,
            "r2": r2_score(y_test, en_pred),
            "mae": mean_absolute_error(y_test, en_pred),
            "rmse": np.sqrt(mean_squared_error(y_test, en_pred)),
            "y_test": y_test,
        }

        # Determine best model
        best_model = max(results.items(), key=lambda x: x[1]["r2"])
        results["best_model"] = best_model[0]

        return results

    def create_regression_plots(self, results):
        """Create side-by-side plots for all regression models"""
        if not results:
            return None

        import plotly.graph_objects as go
        from plotly.subplots import make_subplots

        fig = make_subplots(
            rows=1,
            cols=5,
            subplot_titles=(
                "Linear",
                "Polynomial",
                "Ridge",
                "Lasso",
                "ElasticNet",
            ),
            specs=[[{"type": "scatter"}] * 5],
        )

        models = ["linear", "polynomial", "ridge", "lasso", "elasticnet"]
        colors = ["blue", "green", "red", "purple", "orange"]

        for idx, (model_name, color) in enumerate(zip(models, colors), 1):
            model_data = results[model_name]
            y_test = model_data["y_test"]
            predictions = model_data["predictions"]

            # Scatter plot: Actual vs Predicted
            fig.add_trace(
                go.Scatter(
                    x=y_test,
                    y=predictions,
                    mode="markers",
                    name=f"{model_name.capitalize()} Predictions",
                    marker=dict(color=color, size=8),
                    showlegend=True,
                ),
                row=1,
                col=idx,
            )

            # Perfect prediction line
            min_val = min(y_test.min(), predictions.min())
            max_val = max(y_test.max(), predictions.max())

            fig.add_trace(
                go.Scatter(
                    x=[min_val, max_val],
                    y=[min_val, max_val],
                    mode="lines",
                    name="Perfect Prediction",
                    line=dict(color="black", dash="dash"),
                    showlegend=(idx == 1),
                ),
                row=1,
                col=idx,
            )

            # Add metrics annotation
            metrics_text = f"R² = {model_data['r2']:.4f}<br>MAE = {model_data['mae']:.2f}<br>RMSE = {model_data['rmse']:.2f}"
            # Fix yref for plotly - use 'y domain' for idx=1, 'y2 domain' for idx=2, etc.
            yref_value = "y domain" if idx == 1 else f"y{idx} domain"
            fig.add_annotation(
                x=0.5,
                y=0.95,
                text=metrics_text,
                xref=f"x{idx}",
                yref=yref_value,
                showarrow=False,
                bgcolor="rgba(255, 255, 255, 0.8)",
                bordercolor="black",
                borderwidth=1,
                font=dict(size=8),
            )

            # Update axes
            fig.update_xaxes(title_text="Actual", row=1, col=idx)
            fig.update_yaxes(title_text="Pred", row=1, col=idx)

        fig.update_layout(
            title_text=f"Regression Comparison (Best: {results['best_model']})",
            height=400,
            showlegend=True,
        )

        return fig

    def prepare_lstm_data(self):
        """Prepare time series data for LSTM forecasting"""
        conn = self._db.get_connection()

        query = """
            SELECT
                date,
                SUM(quantity_consumed) as total_consumption
            FROM consumption_patterns
            WHERE date >= DATE('now', '-180 days')
            GROUP BY date
            ORDER BY date
        """

        df = pd.read_sql_query(query, conn)
        conn.close()

        if len(df) < 30:
            return None

        df["date"] = pd.to_datetime(df["date"])
        df = df.set_index("date")

        # Fill missing dates with 0
        date_range = pd.date_range(start=df.index.min(), end=df.index.max(), freq="D")
        df = df.reindex(date_range, fill_value=0)

        return df

    def create_sequences(self, data, seq_length=30):
        """Create sequences for LSTM training"""
        X, y = [], []
        for i in range(len(data) - seq_length):
            X.append(data[i : i + seq_length])
            y.append(data[i + seq_length])
        return np.array(X), np.array(y)

    def train_lstm_model(self, forecast_days=30):
        """Train LSTM model for stock/sales forecasting"""

        try:
            from tensorflow.keras.models import Sequential
            from tensorflow.keras.layers import LSTM, Dense, Dropout, GRU, Bidirectional, Conv1D, MaxPooling1D, Flatten
            from sklearn.metrics import mean_absolute_error, mean_squared_error
        except ImportError:
            st.error("❌ TensorFlow or Scikit-learn not found. Deep learning features disabled.")
            return None

        df = self.prepare_lstm_data()

        if df is None:
            return None

        # Prepare data
        data = df["total_consumption"].values.reshape(-1, 1)

        # Normalize
        from sklearn.preprocessing import MinMaxScaler

        scaler = MinMaxScaler()
        data_scaled = scaler.fit_transform(data)

        # Create sequences
        seq_length = 30
        X, y = self.create_sequences(data_scaled, seq_length)

        if len(X) < 10:
            return None

        # Split data
        split_idx = int(len(X) * 0.8)
        X_train, X_test = X[:split_idx], X[split_idx:]
        y_train, y_test = y[:split_idx], y[split_idx:]

        # Reshape for LSTM [samples, time steps, features]
        X_train = X_train.reshape((X_train.shape[0], X_train.shape[1], 1))
        X_test = X_test.reshape((X_test.shape[0], X_test.shape[1], 1))

        # Build LSTM model
        model = Sequential(
            [
                LSTM(
                    50,
                    activation="relu",
                    return_sequences=True,
                    input_shape=(seq_length, 1),
                ),
                Dropout(0.2),
                LSTM(50, activation="relu"),
                Dropout(0.2),
                Dense(1),
            ]
        )

        model.compile(optimizer="adam", loss="huber", metrics=["mae"])

        # Compare 5 Time Series Models
        def build_stacked_lstm():
            return Sequential([
                LSTM(64, return_sequences=True, input_shape=(seq_length, 1)),
                Dropout(0.2),
                LSTM(64),
                Dropout(0.2),
                Dense(1)
            ])

        def build_bidirectional_lstm():
            return Sequential([
                Bidirectional(LSTM(64), input_shape=(seq_length, 1)),
                Dropout(0.2),
                Dense(1)
            ])

        def build_gru():
            return Sequential([
                GRU(64, input_shape=(seq_length, 1)),
                Dropout(0.2),
                Dense(1)
            ])

        def build_conv_lstm():
            return Sequential([
                Conv1D(filters=64, kernel_size=3, activation='relu', padding='same', input_shape=(seq_length, 1)),
                MaxPooling1D(pool_size=2),
                LSTM(64),
                Dropout(0.2),
                Dense(1)
            ])

        models = {
            "Simple LSTM": model,
            "Stacked LSTM": build_stacked_lstm(),
            "Bidirectional LSTM": build_bidirectional_lstm(),
            "GRU": build_gru(),
            "Conv1D + LSTM": build_conv_lstm()
        }

        best_results = None
        best_mae = float('inf')
        all_metrics = {}

        for name, m in models.items():
            m.compile(optimizer="adam", loss="huber", metrics=["mae"])
            m.fit(X_train, y_train, epochs=30, batch_size=32, verbose=0)
            
            y_pred = m.predict(X_test)
            y_pred_inv = scaler.inverse_transform(y_pred)
            y_test_inv = scaler.inverse_transform(y_test)
            
            mae = mean_absolute_error(y_test_inv, y_pred_inv)
            rmse = np.sqrt(mean_squared_error(y_test_inv, y_pred_inv))
            all_metrics[name] = {"MAE": mae, "RMSE": rmse}
            
            if mae < best_mae:
                best_mae = mae
                best_results = {
                    "name": name,
                    "model": m,
                    "test_pred": y_pred_inv,
                    "test_actual": y_test_inv
                }

        # Use best model for future predictions
        best_model = best_results["model"]
        last_sequence = data_scaled[-seq_length:]
        future_predictions = []

        for _ in range(forecast_days):
            last_sequence_reshaped = last_sequence.reshape((1, seq_length, 1))
            next_pred = best_model.predict(last_sequence_reshaped, verbose=0)
            future_predictions.append(next_pred[0, 0])
            last_sequence = np.append(last_sequence[1:], next_pred[0])

        future_predictions = scaler.inverse_transform(
            np.array(future_predictions).reshape(-1, 1)
        )

        # Create dates for predictions
        last_date = df.index[-1]
        future_dates = pd.date_range(
            start=last_date + timedelta(days=1), periods=forecast_days, freq="D"
        )

        results = {
            "best_model_name": best_results["name"],
            "test_actual": best_results["test_actual"].flatten(),
            "test_pred": best_results["test_pred"].flatten(),
            "future_pred": future_predictions.flatten(),
            "future_dates": future_dates,
            "historical_dates": df.index,
            "historical_data": data.flatten(),
            "mae": best_mae,
            "rmse": best_results.get("rmse", 0), # Added safety
            "mape": np.mean(np.abs((best_results["test_actual"] - best_results["test_pred"]) / (best_results["test_actual"] + 1))) * 100,
            "all_metrics": all_metrics
        }

        return results

    def create_lstm_plot(self, results):
        """Create LSTM forecast visualization"""
        if not results:
            return None

        import plotly.graph_objects as go
        fig = go.Figure()

        # Historical data
        fig.add_trace(
            go.Scatter(
                x=results["historical_dates"],
                y=results["historical_data"],
                mode="lines",
                name="Historical Consumption",
                line=dict(color="blue", width=2),
            )
        )

        # Test predictions
        test_dates = results["historical_dates"][-len(results["test_actual"]) :]
        fig.add_trace(
            go.Scatter(
                x=test_dates,
                y=results["test_pred"],
                mode="lines",
                name="LSTM Predictions (Test)",
                line=dict(color="orange", width=2, dash="dash"),
            )
        )

        # Future predictions
        fig.add_trace(
            go.Scatter(
                x=results["future_dates"],
                y=results["future_pred"],
                mode="lines+markers",
                name="Future Forecast",
                line=dict(color="red", width=2),
                marker=dict(size=6),
            )
        )

        # Add metrics annotation
        metrics_text = f"MAE: {results['mae']:.2f}<br>RMSE: {results['rmse']:.2f}<br>MAPE: {results['mape']:.2f}%"
        fig.add_annotation(
            x=0.02,
            y=0.98,
            text=metrics_text,
            xref="paper",
            yref="paper",
            showarrow=False,
            bgcolor="rgba(255, 255, 255, 0.8)",
            bordercolor="black",
            borderwidth=1,
            font=dict(size=12),
            align="left",
        )

        fig.update_layout(
            title="LSTM Stock/Sales Forecasting",
            xaxis_title="Date",
            yaxis_title="Total Consumption",
            height=600,
            hovermode="x unified",
            showlegend=True,
        )

        return fig
